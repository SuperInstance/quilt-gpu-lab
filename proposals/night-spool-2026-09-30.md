# NIGHT SPOOL — 2026-09-30 (conductor queue; grows; each insight feeds the next)

## PROTOCOL (every wake, ~20 min timebox)
1. Read this file + `tail -40 RESULTS.md`. Check running work (`process list`), never duplicate an IN-PROGRESS item.
2. Take the top OPEN item. New experiment => pre-register in proposals/runs/ FIRST (commit+push before firing).
3. GPU python: /home/eileen/venvs/elephant-gpu/bin/python. Physics conventions: tools/qcell_sim.py (balance=min(p000,p111), angles in pi-units).
4. Book honestly in RESULTS.md (fail-loud anchors; wrong guesses get amended in place, never silently). Commit+push every landing.
5. Append findings below; add new queue items the moment an insight spawns one. Mark statuses so no wake repeats work.
6. ROTATION: after a GPU item, do a PR-SWEEP or SCOUT item next (alternate). PR sweep = `gh pr list -R SuperInstance/<repo>` + read new ones (repos: MicroMoth-quilt, delta-shape, syzygy-lattice, edge-ledger, subleq-fabric, zeroclaw-dissertation) — steal insights, cite PR#, add queue items. SCOUT = web_search for cutting-edge ideas worth rebuilding/forking into SuperInstance paradigms.
7. Do NOT message Casey (asleep). If local time >= 07:00 AKDT: book state, mark NIGHT COMPLETE, start nothing new.

## DOCKSIDE
- [DONE 02:2x PR-SWEEP #2 + RECEIPT-CITE]: only MM #29 merged (docs citation pin). Applied convention to QG1/QG2/QO1 receipts (cite SuperInstance/micrograd-quilt, labs/qcells tree; PRs #5-#7 mirror). Docs-only, pushed.
- [DONE 02:3x] **DECIDE-1c BOOKED (REFUTES flip)**: instruction word largest->smallest changes NOTHING — 5/64 identical accuracy, argmin consistency 0.891 unchanged. Model is instruction-BLIND on this lane, not sign-flipped. STOP rule honored, no re-roll.
  - [spawned by DECIDE-1c] DECIDE-1d (instruction-ablation census): sweep instruction variants {largest, smallest, "highest", "lowest", neutral "Choose one edit.", superlative-only no-definition-sentence} x 64 questions. Map: does ANY phrasing move pred off argmin? If none do, the argmin lock is absolute in the representation -> name it and move on. Cheap (~6 lanes x 2 min).
- [DONE 01:3x] **DECIDE-1 FIRED + BOOKED**: G1 control PASS (16/16=1.0); G2 lane FAIL decisively BELOW chance (5/64=0.078; zero-shot and shipped trained readout give IDENTICAL predictions); G3 PASS (3.31 GiB, 54 ms); G4 exploratory (fitted-T pinned at boundary, fitted head 0.3125 not significant vs 0.25). Per protocol: STOPPED on G2 FAIL, no re-roll.

## QUEUE (top = next)
- [DONE 01:5x] **DECIDE-1b BOOKED (P1 INVERTED FIRED)**: predicted option is argMIN-balance on 0.891 of questions; argmin-prob acc 0.375 (lower CP95 > 0.25); pred_kinds delete=42 vs label_kinds insert=42; shuffle test content_following 0.78 vs letter_stickiness 0.375 (reads CONTENT, not position). The cell answers "smallest balance" — inversion lives in the backbone (both readers identical).
  - [spawned by DECIDE-1b] DECIDE-1c (confirmatory flip): re-run the SAME lane with instruction "...gives the smallest balance?" — prediction: argmax accuracy jumps toward the same 0.89 consistency (mirrored). If it does, the mechanism is a signed-superlative flip, fully characterized. Pre-register before firing.
- [DONE 00:0x] **DECIDE-1 pre-reg + tool + driver WRITTEN** (`tools/decision_cell.py`, `experiments/decide1.py`, `proposals/runs/DECIDE-1-decision-cell.md` + AMENDMENT 1): jeff mechanism fully reverse-engineered — 255x1024 readout head, temperature 1.1289, exact prompt template, answer formulas. Firing blocked only on the 1.7 GB weight download.\n- [DONE 00:0x] **Recons landed**: `proposals/physicalcoding-recon-2026-09-30.md` (1288w) + `proposals/jeff-recon-2026-09-30.md` (1004w + addendum).\n- [DONE 00:0x] QC: `tools/qcell_sim.py` gained the missing `crx` gate + receipt-anchored selftest (k4 champion 0.4268).\n- [DONE 00:0x] QG2 desert-break law: **desert is STRUCTURAL** — exact-arm 57.9% ~= shot-arm 58.2%; ~42% of streams landscape-trapped; G1 FAIL (lane fills desert 0.023 vs recorded 0.017); G2 rate caveat (reimpl 58% vs recorded 3/8; P~0.26 at N=8). results/qg2_desert_law/
- [DONE 01:1x] **QO1 qcell-oracle BOOKED**: G1+G2 PASS, oracle AUC 0.9510 vs baseline 0.8860 (Brier 0.087); features cv>v>gen >> gates. First trained fleet component. Lane torch-nondeterminism ±0.006 noted (all runs in CP95). WAS: train a tiny MLP on QG2 rollouts -> P(cross | champion state: len, balance, gate histogram, gen). Save tools/qcell_oracle.pt + README. First TRAINED fleet component on this substrate. Data: instrument run_lane to dump per-gen champion states + outcomes (4096 streams = 400k+ rows free).
- [open] QG1-residual: localize the 28/1920 anchor mismatches (gate-combo census of failing cells) -> either close to >=99% or name the missing convention.
- [DONE 00:2x PR-SWEEP #1] see FINDINGS.
- [DONE 03:2x SCOUT #1]: see FINDINGS 03:2x. Web search API degraded (503/timeout) — fell back to arxiv API (export.arxiv.org), which worked. Note for future scouts: use the arxiv API directly, no retries on the search provider.
- [open] SL-G1: syzygy-lattice e-process martingale Monte Carlo (port LR rules to torch; operating-characteristic curves: kill-on-impossible, impostor late-cross; validate truth@10/impostor@112 pins first).
- [open] SCOUT #1 (see rotation).
- [open] SF-G1: subleq VM in torch (Int32Array machines, batched) -> program-space census; validate vs subleq-fabric pins.
- [open] DS-G2: change-point GPU engine, synthetic boat telemetry first (the 5-min predictor line = trail() membrane).
- [DONE 03:5x GPU] **QG3 BOOKED**: traps OPEN with generations — C(W6,g24)=0.755 ~= B(W8/g24)=0.763, D(W8,g12)=0.568 ~= A(W6/g12)=0.578. Width is INERT; trap = slow-climb fence (refutes my P1; QG2 structural-desert sharpened: passable at 2x gens). Basin edit-distance metric INCONCLUSIVE (degenerate on short champions; no claim either way).
  - [spawned by QG3] QG6 (variance rescue): stuck streams on shallow gradient — try temperature-style bigger mutations (k-gate block edits, k in {2,3}) at FIXED total children. Does variance, not more generations, rescue the slow climbers? Tests selection-pressure vs move-set explanation.
  - [spawned by QG3] QG3b (basin observable fix, cheap): re-cluster stuck champions by champion STATEVECTOR distance (unitary output overlap) instead of genome edit distance. Only if QG6/QO2 needs basin identity.
- [open | NEXT GPU] QO3 (early-forecast horizon): at which gen does oracle AUC first clear 0.80? If gen<=3, crossing near-deterministic early -> feeds QO2 routing directly. QG3's slow-climb result says late-gen information matters — test which.
- [spawned by QG2] QG4: budget/gens phase diagram (W x gens grid, 1024 streams/cell) — map the crossing frontier. Directly serves "cells are dedicated; routing happens between cells".
- [spawned by PR-SWEEP #1] RECEIPT-CITE: amend QG1/QG2 receipts (proposals/runs/*.md) to cite SuperInstance repos by name (weight law; see MicroMoth-quilt PR #29). Docs-only, no re-run.

## FINDINGS (append-only)
- 00:0x CONDUCTOR-0 (main): QG2 headline above. qcell-sim gained crx + receipt-anchored selftest. Vectorized lane = gathers + bmm chains; ANCHOR-VEC 2e-34.
- 00:2x PR-SWEEP #1 (conductor): 6 repos swept; only MicroMoth-quilt active. **PR #29 OPEN** — docs-only provenance: qcells lab canonical home = SuperInstance/micrograd-quilt; cite repo not local path in receipts. Clean (fail-first pins, 248/249; 1 pre-existing main-tip manifest drift, remedy already in PR #25 stack). Merged highlights: #28 exp022 train-visible crossing census (tie-break-invariant), #27 rate-not-wall + desert-extends-to-cloud, #26 tie-band-diversity replicated, #25 archive-assembly + manifest regen, #24 fitness desert at birth cloud (29/31/37). **Steals:** (a) weight-law by-name citation -> spawned RECEIPT-CITE item; (b) exp018 desert-at-birth-cloud independently corroborates QG2 structural-desert — desert is upstream of selection, now two lanes agreeing; (c) note bookkeeping discipline: my first spool edit clobbered the QG4 queue line; caught + restored same wake. Always re-read the file after structural edits.
\n- 00:45 CONDUCTOR-0 (main): PhysicalCoding + jeff recons landed; DECIDE-1 armed behind the weight download; qcell_sim crx fix (tool had been missing a gate the telemetry uses since QG1 — caught by the QG2 anchor).\n- 01:1x CONDUCTOR slice (night cron): QO1 landed (see RESULTS.md). Two spawned items:
  - [spawned by QO1] QO2: oracle-guided routing — use qcell_oracle.pt P(cross) to allocate remaining budget across streams (kill low-P streams early, resample high-P). Does oracle-guided selection beat uniform selection at equal total child-evaluations? Directly tests "routing happens between cells".
  - [spawned by QO1] QO3: early-forecast horizon — at which gen does oracle AUC first clear 0.80? (train per-gen classifiers). If gen<=3, crossing is near-deterministic early -> desert streams are visible at birth, feeding QG3.
- 01:3x CONDUCTOR slice (night cron): DECIDE-1 fired on landed weights and booked. Headline: jeff-0.8b's decision
  mechanism is intact (control 16/16) but the balance-edit lane reads BELOW chance (0.078 vs 0.25 random) — and the
  shipped trained readout and zero-shot head give byte-identical wrong predictions on the lane. Below-chance
  symmetric failure is information: the backbone encodes a consistent-but-wrong decision signal for this question
  family. Spawned DECIDE-1b (diagnosis before anything else on this lane). Fail-loud trail: 3 mechanical crashes
  fixed in place pre-scoring (chat-template fallback bypassed in arm C, device split, str-vs-int labels); honest
  note: the fitted-T optimizer pinned at the 6.0 boundary — flag for any future temp-fitting on near-zero-signal
  logits. 20-min slice complete; ~02:00 next wake should take DECIDE-1b (GPU) then PR-SWEEP per rotation.
- 01:5x CONDUCTOR slice (night cron): DECIDE-1b landed. Headline: **the below-chance lane is INVERTED, not
  broken** — jeff-0.8b picks the argmin-balance (worst) edit on 89% of questions, prefers delete-type
  options (42/64) where truth is insert-type (42/64), and follows option CONTENT under shuffling (0.781)
  rather than letter position (0.375). Both readouts identical => inversion is in the backbone representation.
  Hypothesis (untested): superlative-direction flip — the cell tracks "balance" but answers "smallest" when
  asked "largest". Spawned DECIDE-1c (instruction-flip confirmatory). Next wake per rotation: PR-SWEEP #2
  (GPU item just landed), then DECIDE-1c.
- 02:2x CONDUCTOR slice (night cron): PR-SWEEP #2 (only MM #29 merged; citation convention applied =>
  RECEIPT-CITE DONE, QG1/QG2/QO1 receipts amended docs-only) + DECIDE-1c fired and booked. Headline: the
  superlative word in the instruction has ZERO causal effect on jeff-0.8b's choice (identical 5/64 across
  largest/smallest); the argmin-balance lock is instruction-blind while the numeric control lane reads
- [DONE 02:5x] **DECIDE-1d BOOKED (lock ABSOLUTE)**: argmin consistency 0.844-0.891 across all 6 phrasings (largest/smallest/highest/lowest/neutral/no-def); argmax acc 0.078-0.125; neutral = identical to largest. Named **representation-locked argmin**. DECIDE lane CLOSED tonight per STOP rule.
  - [spawned by DECIDE-1d, day-item for Casey] DECIDE-2 (representation surgery, NOT a night item): linear probe on pre-readout hidden states — does the argmax-balance signal exist upstream of the routing? If yes, LoRA/head-retrain fix is cheap; if no, the ordering itself is encoded inverted. Needs new instrumentation in decision_cell.py.
  superlatives fine. Signed-flip hypothesis dead. Spawned DECIDE-1d (instruction-ablation census).
- 02:5x CONDUCTOR slice (night cron): DECIDE-1d fired and booked (census: lock absolute across 6 phrasings,
  named representation-locked argmin; DECIDE lane closed per STOP). Spawned DECIDE-2 (representation surgery,
  day item — needs Casey's eyes + new instrumentation). Rotation for next wake: non-GPU per rotation
  (PR-SWEEP #3 or SCOUT #1), then QG1-residual/QG3/QO3 per queue order.
- 03:2x CONDUCTOR slice (night cron): SCOUT #1 landed (non-GPU per rotation; last slice was DECIDE-1d GPU). Source:
  arxiv API fallback (search provider 503 — one alternate route, no retry loop). Six live steals, ranked:
  1. **EvE "An Alternate Optimizer to Adam" (2609.36xxx)** — configs ranked CHEAPLY and pruned EARLY in search
     budgets. Maps directly onto QO2/QO3: oracle-guided pruning is the same doctrine; steal any early-ranking
     metric ideas for oracle features. Spawned QO4 below.
  2. **CMDO: Cognitive Memory-Driven Optimization** — population search retaining the CONTEXT where behaviors
     succeeded/failed. Mirrors QO1 oracle + QG3 desert clustering: routing should remember *why* streams died,
     not just that they died. Feeds QG3 design (basin memory features).
  3. **"Where Does Randomness Matter in Neural Cellular Automata?"** — separates train-time vs execution-time
     update randomness. Directly relevant to qcells: our structural-desert law says trapping is upstream of
     selection; this paper's train/exec randomness split is a ready-made ablation frame. Spawned QG5 below.
  4. **KACS: Kolmogorov-Arnold Classifier Systems (IEEE TEVC 2026)** — rule count O(m^n)->O(mn^2) via
     dimension-wise decomposition; first LCS universal-approximator proof. Speaks to "cells are dedicated;
     routing happens between cells": per-dimension dedicated rulesets + superposition. Candidate frame for
     qcell rule-space scaling. Spawned QC-KA below (reading item first).
  5. **"Evolving Towards Better Codes: LLM-Guided Search"** — record-breaking combinatorial constructions via
     LLM-driven evolutionary search. Directly relevant to subleq-fabric program-space census (SF-G1): the
     harness pattern (LLM proposes mutations, exact verifier accepts) is exactly our lane. Read before SF-G1.
  6. (minor) iSOMA-AR adaptive rotation — learns a basis from successful migration displacements; long-shot
     idea for qcell routing if basins show shared geometry.
  Spawned queue items: QO4, QG5, QC-KA. Rotation honored (GPU last, non-GPU this). Next wake: GPU — QG3
  (marked NEXT GPU) or QG1-residual per queue order; pre-register before firing.

  New queue items spawned by SCOUT #1:
  - [spawned by SCOUT #1] QO4 (early-ranking steal): read EvE paper; extract its cheap early-ranking signal
    and test as an oracle FEATURE alongside cv/v/gen (does EvE-style momentum of champion fitness improve
    QO1 AUC 0.951? Does it clear 0.80 earlier than QO3's per-gen horizon?).
  - [spawned by SCOUT #1] QG5 (train-vs-exec randomness in qcells): NCA-paper ablation frame — does desert
    trapping depend on update-randomness at roll-in vs roll-out? Instrument run_lane with a deterministic-
    rollout arm (fix champion stream RNG at eval). Cheap, feeds QG3.
  - [spawned by SCOUT #1] QC-KA (reading, non-GPU): read KACS paper + repo (YNU-NakataLab/KACS); write a
    1-page note on whether Kolmogorov-Arnold dimension-wise decomposition applies to qcell rule space.
