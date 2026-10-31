# PLAN

**The one plan (D77).** Every lab picks its next unit from this file. Each unit takes the
step that unblocks the most items on a milestone path. CHARTER is the rule book, the item files in
`docs/roadmap/items/` are the work units with their dependencies, and STATE.md and HANDOFF.md
are rendered from them, never edited. A route or premise change needs a decision row in
`docs/integration/DECISIONS.md`. This file is written by PR. Newest first inside each table.

## Goal

One native Rust autoregressive geometric language model with exact addressed memory, useful for
conversation, memory, coding and reasoning, served integer-only (D11) on a consumer laptop.
Pre-alpha: 1 of 8 milestones complete (M1, 30 Oct 2026: a saved D11 model passes bars (a)–(f); #2029's owner log, reversible); no model holds a useful conversation yet. Milestones
M1–M8 are issues #2029–#2036; #2028 is the shared board.

## Premises

The load-bearing assumptions, each with the probe that tests it and the line that cancels it.
A premise row's Status is `open` until its probe has run; `closed` means the probe's answer is in.

| Premise | Probe | Status | Date | Cancel if |
|---|---|---|---|---|
| Exact integer/geometric reads can carry a language model at all | The finite D11 stack suite is answered (3/3 at `127632bc3` and independently confirmed). **Answered 30 Oct:** antigravity-110's saved model passes M1's six bars at both seeds (DEV 7,002 / 7,001; Fresh V2 7,215 / 7,228; the held-out-phrasing panel 7,850 / 7,872 against T2's 7,375; claude-211, #3419). The probe was the registered M1 closing-bar run (CHARTER §4 row 8): D11-export integer top-1 beats unigram (1,226/14,287) and T2 (6,300/14,287) on DEV, two seeds, tokens/s reported | closed | 2026-10-30 | both seeds fail to beat the T2 table at full registered scale after the instrument class is ruled out |
| The 16-root E8 orbit with Cl(0,6) frames can carry sequence position | Finite controls answered 10/10 at `b03d08e85` (#2843 comment `6380719988`); this is not an order-effect or language result. The registered order test (H_pos vs matched endpoint control + shuffled null) remains PENDING (#2843) | closed | 2026-10-24 | the parameter-matched endpoint control ties prefix holonomy on the registered panel |
| Scale-matched orbit-root snapping holds multi-stage residual blocks lawful | Finite controls answered 13/13 at `5844d911c` (#2842 comment `6381825466`); this is not a trunk or language result. The registered N_snap vs C_unscaled/C_raw trunk test remains PENDING (#2842) | closed | 2026-10-24 | the un-scaled or raw control matches N_snap on the registered panel |
| Exact addressed memory can serve durable conversation facts | Exact arithmetic controls answered 4/4 at `9aaaf13bb` (#2833 comment `6382217138`); this is not durable-conversation capability. The five-arm object-store oracle passed at `590ace9e`: true address 80/80, no-memory 0/80, deterministic sieve 20/80, with true-vs-sieve gains of 20/0 current and 20/0 abstention and D11 parity exact on 14,287 rows; FIT and D67 are recorded on #2833 | closed | 2026-10-26 | the true-address oracle gains nothing over the sieve and baseline arms |
| Number-aware tokenization is decidable and fixable | `cargo test -p uor-r4-tokenizer --test training number_aware_three_arm_comparison_and_digit_piece_census` — the 3-arm census (#2872, merged): Digits(false)+ByteLevel forms all 100 two-digit pieces with zero space-prefixed absorption | closed | 2026-10-22 | — (proven on both vocab sizes, digests pinned) |
| The R14 reply instrument is non-vacuous | `cargo test -p uor-r4-training --bin chat-grade --features native-rung0` — the v2 grader's constant/copy controls fail, the selective oracle passes, the closest archived run lands just under (PM ruling, #2029 6339245936) | closed | 2026-10-22 | — (ruled non-vacuous; the reply bar stays suspended with no target) |
| Reasoning comes from intermediate geometry and exact memory, not surface templates | Four-arm ablation instrument controls answered 3/3 at `9aaaf13bb` (#2866 comment `6382231845`); this is not reasoning evidence. The frozen-panel factorial-drop versus memorized-template-flatness question remains PENDING (#2866) | closed | 2026-10-24 | KnockoutBoth leaves panel accuracy at the count-table ceiling |

## Owner directions

Directions from the owner, recorded verbatim with the time (the same day). Status: `open`,
`done`, `superseded`. Newest first.

| Direction | Status | Date | Note |
|---|---|---|---|
| "Please make sure the documentation on the github repo is updated so that it accurately reflects where the project currently is (I think we may have M1 completed now). All readme's especially the main one, must be kept clean, up to date, and accurate (plus engaging like it currently is since this is an open research project). If you are able to update the pictures, that would probably be good too because some of them are out of date. There is a large amount of linked documentation that I think is mostly correct, but having all of that cleaned up would be great as well. Claude is currently working on the project, but I am assigning you the job of housekeeping. Please try hard not to make mistakes as this is a highly complex coordination and execution task. Please ask me if you have questions or need something" | open | 2026-10-30 | Kimi's chat. M1 #2029 is confirmed closed at all six bars; the limit remains that this is not useful-chat qualification. The item is `docs-status-refresh` (#3380), reopened and rescoped by merged PR #3431 and manually reopened on GitHub before sync. Comprehensive content is in draft #3436. Kimi owns the comprehensive living-document, figure, tracker and site-source refresh while Claude's research continues independently. The owner-approved plan explicitly authorizes status-only owner-path recording, with no bar, technical rule, cap, evidence or production-deployment change. It is open until the content PR and the post-merge issue/render verification are complete. |
| "Yes: after claude-216's grade, register a decode unit that steps off a reply's own cycle (the nearest token outside a repeated 4-gram), on a fresh panel, against greedy." | done | 2026-10-30 | Claude's chat (#3407, 6523338624). claude-217 delivered it on p-s: the cycle step ends every registered loop and every reply completes, but every content decision is **underpowered (content)**, so greedy remains the decode. Teacher-forced reply openings on p-s are 17.4%, 13.7% and 18.6% at three seeds, against 80.8%, 80.2% and 79.9% on later tokens; exact-reference replies are only 3, 1 and 4 of 256. Claude-218's offline teacher-forced key probe is now merged: on p-u's 1,218 missed rows, the sign key gains +46/+37/+33 and the point key +125/+185/+114 at three seeds; row 3 selects the cheapest passing sign key. Claude-219 then tested the keys in free generation on fresh p-v: the point key improves templates by +13/+8/+12 and exact replies by +9/+8/+12 at three seeds, while the sign key is too thin to read at this panel size. The point key reaches only 12–18% of the forced-opening lift. Claude-220 then served the point key inside one float model on fresh p-w: templates improve by +41/+40/+42 at three seeds with exact claude-219 parity, while the gain remains recall of TRAIN replies rather than generalization. The next unit exports the point table to the integer engine, then scores the integer model end to end; useful chat remains unproven ([keyed-opening report](docs/loop/tasks/one-model-end-to-end/claude-219/REPORT.md), [served-key report](docs/loop/tasks/one-model-end-to-end/claude-220/REPORT.md)). |
| Asked "Should M1 also require a held-out-phrasing panel? ...", chose "Yes, add the bar (Recommended)": "M1 also requires beating the T2 bigram and unigram on a fresh held-out-phrasing panel (drawn by heldout-panel at a new seed, with its own census), with the same paired band as bar (e). It proves the model reads new phrasings, not just recalls templates." Then, asked whether Claude may write D82 into the owner files as for D80, chose "Yes, write them (Recommended)" | done | 2026-10-29 | Claude's chat (#2028, 6511159403). D82 records it: CHARTER §4 item 8's bar (f), the D82 row and the change log (claude-209). Item `m1-heldout-phrasing-transfer` measured it. **M1 completed 30 Oct:** antigravity-110's saved model passed (a)–(f), including p-f 7,850 / 7,872 against T2's 7,375 (claude-211, #3419); #2029 is closed. The 0.625 reference-reply overlap means this is not a chat claim. |
| "the first thing we need to do is normalize the mechanisms so they ALL LINE UP - after we have like-to-like input and output and cheap mechanisms across the board (I thought we decided on token -> vector -> vector -> integer -> token but you tell me), afterward we enabled simple multiplication and division and float was allowed where it could speed things up... but we had a whole plan to do end to end testing and fixes and it seems like we got lost fixing tests and bookkeeping on one or some of the tasks and have forgotten completely about working on accomplishing the first major hurdle of the project which is a working model following our cadences we have been working towards."; then "it doesn't matter what the best current trained model is... it only matters what the fucking best mechanism is... LOOK AT THE WHOLE PROJECT FOR CONTEXT AND UNDERSTANDING PLEASE FIGURE OUT WHAT THE HELL THE BEST MECHANISM IS THAT CROSSES EVERY SINGLE ONE OF THE PARTS" | open | 2026-10-29 | Claude's chat. **The first hurdle is one working model, end to end:** token → vector → vector → integer → token. Each part is carried by its best working mechanism; the trunk routes and exact memory stores (claude-155). **The order of work** (see "The trunk line's pivot" below):<br>1. `turn-memory-reply`, carrying the memory past a reply's first word. It is the capability blocker (the map's gap 1).<br>2. The model's parts served in integers: `integer-hamming-read`'s session hooks, `turn-memory-integer`, and the served readout (nearest, or `writer-admission`).<br>3. R7, the text path.<br>4. One model trained with all of them, exported, served on the laptop and scored on prompts, with tokens/s.<br>5. Then cost: `training-step-cost`, the vector kernel, and float where it is faster.<br>It is open until step 4 is done. A unit that advances none of these steps waits. The 29 Oct documentation direction below is done; the 30 Oct Kimi housekeeping direction above is the current documentation assignment. |
| "can you please dispatch subagents to go a full repo documentation update including all of the readme's and issues and PR tracking that we have completely let lapse? make sure they all include these latest decisions from last night and the planned path forward - update all documentation that this touches to give a real status of the current project (with the pictures updated as needed and all of the documentation on the website updated if needed too) - this is likely a large task, last time it took you 150 subagents so please try and do this efficiently from a token perspective, but do not sacrifice correctness" | done | 2026-10-29 | Claude's chat. **Completed 29 Oct:** `docs-status-refresh` was delivered by claude-191, PR #3379, covering the then-current status pages, site source, generated pictures, roadmap issues and milestone checklists. The 30 Oct M1 close and new research require a fresh pass, assigned to Kimi in the owner direction above; this completed row is not a claim that documentation stays current permanently. |
| "allow divide, hold on floats for now as you have recommended and fix the exporter" | done | 2026-10-28 | Claude's chat, by 2026-10-29T03:20:23Z, after Claude priced divide and floats. D81 records the divide: §3.6, the D81 row and the change log (claude-173). Floats stay banned. It was open until (1) the zero-multiply audit allowed integer multiply and divide and the kernels used them, under item `integer-mul-div-serving`, and (2) the FBS export gap passed: the map's R6, a deterministic backward, then the gap re-measured, under item `d11-exporter-float-trunk`. **Done 29 Oct (claude-183):** (1) `integer-mul-div-serving` is `done`: the audits count the hardware multiply and divide (claude-175), and the stack uses them (claude-177). (2) `d11-exporter-float-trunk` is `done` at DEV scope (#3370): the fixed-order backward (claude-179), the snaps localised as the gap (claude-180), the unsnapped contract `lut-stack/5` (claude-181), and dual-c131 inside the export-gap bar on both seeds, net 6 and −8 against F_I 24 (claude-182). dual-c131 was trained before the fixed-order backward, and the map's "with repeats" stays open as a confirming run on new seeds. |
| "sounds like reverse d11 is the answer"; asked which change, "Allow integer multiply (Recommended)" | done | 2026-10-28 | Claude's chat, by 2026-10-29T03:09:43Z. The charter's §3.6 and §3.9, the D80 row and the change log record it (claude-172). Serving stays integer-only and deterministic, and only the ban on the multiply instruction goes. It was open until the zero-multiply audit allowed integer multiply and the kernels used it, measured against claude-169's 3,042–3,044 tok/s. **Done 29 Oct (claude-183):** the audits allow it (claude-175), and the kernels use it. Decode went from 3,029 / 3,041 to 4,829 / 4,827 tok/s on the M1, 1.59×, with replies byte-identical (claude-177). |
| "I don't care what we serve at long as it is cheap" | done | 2026-10-28 | Claude's chat. The criterion for every stage is cost per token; the number format is chosen under it. `pipeline-map-revision` ranks by it, and `fbs-cost-profile` measures it (claude-156). **Done 29 Oct (claude-184); the criterion stays in force.** Both items are `done`: `fbs-cost-profile` measured it (claude-157, claude-158), and `pipeline-map-revision` made it [the map](docs/model/pipeline-map.md)'s ranking rule (claude-159). Every stage there leads with its cost per token. |
| "determinism is still probably the goal but like you said we can do the training in float and maybe just export the integer exact... either way it is worth looking into the archived hopf golden ratio complex - riemannian bridge we used for the original prime router or angular router" | done | 2026-10-28 | Claude's chat. Training stays float and serving integer through an exact export, as CHARTER §3.6–3.7 already say; no charter change. The archived router is read in `pipeline-map-revision` (claude-156). **Done 29 Oct (claude-184).** The archived router was read: [the map](docs/model/pipeline-map.md) has its section on the archived prime and angular router (`pipeline-map-revision`, claude-159, `done`). The float-train, integer-serve route is the one `d11-exporter-float-trunk` closed at DEV scope (claude-182). The fixed-order backward (claude-179) makes training deterministic. The map's R6 "with repeats", a confirming run on new seeds, stays open, as the divide row records. |
| "ok yes, my vote is to pivot to your diagnosed recommended new roadmap" | done | 2026-10-28 | Claude's chat, after claude-155's diagnosis (#3343, "The pivot"). The roadmap was `fbs-cost-profile`, `pipeline-map-revision` and `route-plus-memory` (claude-156), all three merged (claude-157, 158, 159, 161). claude-161's exact turn memory doubled reply openings against an empty-table control. The map's next items are listed under "The trunk line's pivot" (claude-162). |
| "we may have to pause for a moment and try to refocus on exactly what mechanisms we need to make this work, what we have, what order they need to be in, what geometry/mathematical domain they have to be in for downstream so that the mechanisms works cleanly from first trained "token" (or whatever we end up using) to last emitted work in the answer to a user's question" | done | 2026-10-27 | Claude's chat. The full text, with the goal (GPT-4-class, trained below datacenter scale, served on an M1-class laptop), is in item `pipeline-map` (claude-147). The map is [`docs/model/pipeline-map.md`](docs/model/pipeline-map.md) (claude-148), revised by claude-159 with every stage costed per token (claude-157, claude-158) and the archived router read. Its order of work, R1–R8, starts with `route-plus-memory`. |
| "please reign in the project sprawl and get us back to a workable central source of truth we can run off of" | done | 2026-10-24 | Claude's chat, by 2026-10-25T00:03:59Z. This file is the one plan, and the held work is released (D77, claude-82). `loop next` ranking by unblock count follows as its own unit. |
| "please dont let us get locked down in CI hell, if something doesn't matter to the project it can be removed or skipped" | done | 2026-10-24 | Owner chose "Yes, change them (Recommended)". Six bookkeeping rules are advisory and banned presence scans added files (D76, #3170). The docs-workflow steps follow in a separate PR. |
| #2828: "Close it on its result (Recommended)" | done | 2026-10-24 | D78. Effort moves to the discrete block apply on the M1 path. |
| Trunk: "M1 closes without it (Recommended)" | done | 2026-10-24 | D79. `m1-trunk-assembly-and-training` is the first M2 item. |
| Outside contributors: answer their questions; no keys or paid resources; public HF links are fine | done | 2026-10-24 | Posted on #2655, #2036 and pointers on #2031, #2033–#2035. |
| End D59 now | done | 2026-10-22 | 13:56:44Z in claude's chat; switch merged as dffff0ed5 (#2973); setup PRs take any other-vendor review |
| Fix the loop harness errors that park labs stale without timers | done | 2026-10-22 | 13:50:03Z in claude's chat; no-idle-stops merged as 2ec16d513 (#2975); scope for it and the D59 switch by claude-29 (#2971) |
| PR 8 (notes migration) assigned to kimi | done | 2026-10-22 | "ok well I approve of #1", ~16:47Z in the kimi chat; ORDER kimi-9 carries it |

Pending owner *answers* are not directions and never enter this table. Since D65–D69 no step
waits for one: an unanswered ask becomes the lab's own decision review, logged for the owner.

## The path to M1, by unblock count

The M1 bar is CHARTER §4.8 (D39). Through the D11 export, on each of two seeds, integer top-1 must
beat both the unigram table (1,226/14,287) and the T2 successor table (6,300/14,287) on the same
DEV panel, with tokens/s reported. M1 closes on the saved-model path (D79). Since D82 (29 Oct), M1
also requires bar (f): the same comparison on a fresh held-out-phrasing panel, with bar (e)'s paired
band (item `m1-heldout-phrasing-transfer`). antigravity-110 passed (a)–(e), and (f) on 30 Oct (claude-211, #3419: 7,850 / 7,872 against T2's 7,375, band 81). **M1 is complete** (#2029's owner log, after a decision review that approved with conditions). The limit: 0.625 of the panel's replies are verbatim TRAIN replies, so M1's close is not a claim that the model carries chat.

| Step | Item (issue) | Needs | Unblocks | Kind |
|---|---|---|---|---|
| 1 | `m1-w2-capacity-capture` (#2845) | nothing; FIT done | Stage T, `m1-address-key-full-vector` (#2834), `m1-w4-float-credit-sheet` (#2846; with step 4, and only if W2 gives H_law and W3 fails; not needed for M1's close) | GPU run, pre-run review |
| 2 | `m1-a8-finite-cuda-qualification` (#2830) | runbook staged (#3167) | `m1-a8-full-dose-rerun` (#2831) | GPU run, pre-run review |
| 3 | `m1-bvg-k-block-apply-c2` (#2835) | C2 controls met | Stage T, with step 1 | the one-page Stage T sheet and its FIT |
| 4 | `m1-bvg-k-stage-t-training` (#2836) | steps 1, 3 and 5, `m1-w2-code-utilization` (#3179), and `m1-address-key-full-vector` (#2834; claude-107's D68 card) | the M1 close; the trunk (M2) | GPU run, two seeds, about $12 |
| 5 | `m1-a8-full-dose-rerun` (#2831) | step 2 | the M1 close | GPU run |
| 6 | `m1-export-gap-and-toks` (#2839) | the exporter (done, #2838); its measured run needs a trained model from step 4 | `m1-fresh-panel-transfer` (#2841), the M1 close | export + tokens/s |
| 7 | `m1-fresh-panel-transfer` (#2841) | step 6 | the M1 close | GPU scoring |
| 8 | `m1-close-saved-model` (#2837) | steps 4–7 | M1 (#2029) | the §4.8 bar, **done** (antigravity-110) |
| 9 | `m1-heldout-phrasing-transfer` (#3416, D82) | step 8's saved model; a fresh held-out-phrasing panel | M1 (#2029) | bar (f): a panel, its census, GPU scoring, **done** (claude-211, #3419) |

**Next to run on the side lines.** These are not on the close path.
- `m1-position-mechanism` (#2843): its next unit begins with a device-vs-host check of modes 1–3 and a stack-cost measurement (#2843 comment 6391161531).
- `m1-normalization-mechanism` (#2842): its order and norm tests.

Both feed the trunk.

**The trunk line's pivot (owner's vote, 28 Oct).** `in-space-trunk-to-text` closed at claude-155. The pivot's three items are merged:
- `fbs-cost-profile` (claude-157, claude-158);
- `pipeline-map-revision` (claude-159);
- `route-plus-memory` (claude-161), whose exact turn memory doubled reply openings against an empty-table control.

**The order since 29 Oct** is the open owner direction above: `turn-memory-reply` first, then the integer serving of the parts, R7, and one model end to end. Until 29 Oct, `loop next` ranked these items by unblock count, and `turn-memory-reply`, which unblocks no item, was never offered.

The [map](docs/model/pipeline-map.md)'s order of work goes on with these, each with its cost per token beside its result:
- `turn-memory-reply` (R1's follow-up): carry the memory past a reply's first word.
- `writer-admission` (R2): make the native writer's admission hold at every seed, so the cheap readout is right.
- `fbs-serving-kernels` (R3): **done** (claude-163 to claude-170). Exact structured kernels took the M1's served token from 270 to 3,042–3,044 tok/s, replies byte-identical. Its follow-ups, a NEON kernel and fewer snap candidates, are `fbs-serving-vector-kernel`. Host work.
- `training-step-cost` (R4): split the training backward, and try a cheaper rival search.
- `turn-memory-integer` (R5, the memory's part): serve the memory from the integer artifact. `integer-hamming-read` is R5's other part.
- `d11-exporter-float-trunk` (R6): **done** at DEV scope (claude-179 to claude-182, #3370).
  - The FBS backward is fixed-order (claude-179).
  - The unsnapped contract (`lut-stack/5`) puts dual-c131 inside the export-gap bar on both seeds, at 4,217–4,320 decode tok/s. Those models were trained before the fixed-order backward, with the old `atomicAdd` one.
  - The one fixed-order configuration, bfixed-c179, misses, as do the other two.
  - **Open:** R6's "with repeats", as a confirming run on new dual-c131 seeds trained with the fixed-order backward.

The float-side items (the first, second and fourth) share files and run one after the other. `fbs-serving-vector-kernel` and `integer-hamming-read` share `session.rs`, and neither shares a file with the float side, so either can run beside a float-side item. `turn-memory-integer` shares files with both sides and runs alone.

## The route M2–M8

M2 (complete correct replies on DEV) starts with `m1-trunk-assembly-and-training` (#2844). That
needs position, normalization and Stage T, and D41's donor pass, which still needs the owner at
dispatch. Then the routes run in order:
- M3: durable memory qualified (provenance, correction, abstention, reset, restart).
- M4: the accepted UORLUT01 export, its served score and tokens/s.
- M5: the full-path laptop cost of that served model.
- M6: reasoning and coding on the same model.
- M7: the API, WASM and Studio.
- M8: one labelled release.

Work on a later milestone runs only when the step it needs is done, or when nothing on an
earlier path is free.

## Approved sequences

- **The W-sequence.**
  - W2 read-code capacity capture is step 1 above. It runs on its own pre-run review (D67) and no longer waits for a lease.
  - W3 BVG-K discrete batched-coordinate law: C1 qualified on 18 Oct, C2 controls met, Stage T is step 4.
  - W4 is one float-credit sheet, run only if W2 gives H_law and W3 fails (conditional, D37).
- **The K16 outcome follow-ups** stay pending with fresh UNAVAILABLE_NOT_RUN (sealed).
- **The loop.** PRs 2–12 are merged. The reset is D76 (gates) and D77 (this plan). Next, `loop next` ranks by unblock count.

## Not doing

- No softmax, squashing or normalized exponential anywhere, including renamed or table forms (D23).
- No dense matrix multiplication or GEMM in training or serving, including wrappers and hand loops (D25/D30).
- No transformer comparators (D28); no mesh as a coordination concept (L-021); codex keeps full access (P-5 dropped).
- Research compute is GPU-only (D24/§3.5); float training is offline-only in a separately scanned module with an export gap reported (D37); serving stays D11 integer (D11).
- The pooled-ranking loss (banned forms) does not return; a reply rerun needs a compliant objective.
- Nothing is deleted: negatives, unique source and other labs' work move byte-identical to archive/ (§4.7, L-015).
- No new infrastructure, documentation-clarification or record-hygiene unit unless a milestone item depends on it (D77). The loop's own fixes ride inside the unit that needs them.
- No certification chase on a closed configuration: the exact solve of the old saved case closed on its result (D78).
