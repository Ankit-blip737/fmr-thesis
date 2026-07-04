# RESULTS_LOG.md — running verification log (append-only; tag [A] or [B])

- **[A] 2026-07-03 session start.** Resumed at commit `1d9730a`. Verified env: Python 3.12, numpy 2.2.2, scipy 1.14.1, sklearn 1.8.0, matplotlib 3.9.0, torch 2.12.1+cpu (no CUDA), PIL 10.4.0. transformers/datasets not installed yet. Building Signals B/C + fusion + conformal abstention, then running the full mock pipeline. Entries below carry actual numbers as runs complete.

- **[A] 2026-07-03 — Bug fixed (Region geometry).** `Region.__post_init__` read `self.x0`/`self.y0` *after* overwriting them, collapsing any reversed-corner box (x0>x1) to zero area. This silently corrupts Signal B IoU for any box whose corners arrive unordered (real SLAKE/VQA-RAD boxes do). Fixed by snapshotting all four coords first. Regression test `test_regions.py::test_coordinate_normalization` added and passing.

- **[A] 2026-07-03 — Test suite: 25/25 pass** (`pytest fmr/tests`). Covers Region geometry, synthetic data + disjoint splits + held-out modality, MockVLM determinism/temperature/chain-length, all three signals' direction + realistic AUROC band + fusion-vs-single, record-schema contract, and the SGR guarantee (empirical violation rate ≤ δ across 60 worlds).

- **[A] 2026-07-03 — Stage 2 baselines (mock, synthetic n=4000, test=1000).** mock-reasoner and mock-plain both acc=0.863 overall (per-modality 0.842–0.893). Identical by construction (same `_pref`); the models differ only in chain length/drift, which is what Signals B and the drift experiment probe — accuracy alone can't tell them apart, exactly the proposal's point that "accuracy hides it."

- **[A] 2026-07-03 — Stage 2 BLIND TEST (headline hypothesis, mock).** acc(original)=0.863, acc(blank)=0.332, acc(mismatch)=0.344 → **blind_gap=0.531**: removing the image collapses accuracy toward chance (1/6≈0.167 floor + lucky priors), i.e. the answer genuinely depends on the image in the mock. **Grounding-drift curve (reasoning model), mean IoU vs GT by step index: s0=0.321, s1=0.283, s2=0.264, s3=0.218** — monotonic decay along the chain. This *replicates the "more reasoning → less grounded" effect* in the (synthetic) medical setup, validating the machinery that will test it on real models. NOTE: this is mock data by construction — the real test is the Colab run; logged as machinery-validation, not as the empirical finding.

- **[A] 2026-07-03 — Stage 3 signal validation (mock, test=1000).** AUROC vs hidden grounding latent: **Signal A=0.819, Signal B=0.739, Signal C=0.770, fused FS=0.870, confidence=0.862.** Fused FS beats every single signal (max single 0.819) — direct evidence the multi-signal fusion helps, and a target for Instance B's learned verifier to beat. Class-mean gaps all correctly signed: A +0.244, B +0.118, C +0.259, FS +0.211, IoU_mean +0.183 (grounded > ungrounded throughout). Manual inspection of 10 examples: signal directions sane (grounded samples show high consistency + tight IoU; ungrounded samples with lucky-prior-correct answers correctly get low B/IoU).

- **[A] 2026-07-03 — Stage 5 conformal abstention (mock, α=0.05, δ=0.05, cal=1000, test=1000).** FS gate: τ=0.372, feasible, **coverage(test)=0.551, retained error(test)=0.0163 ≤ 0.05 ✓ guarantee holds**, AURC=0.0341. Confidence gate: τ=0.563, coverage=0.549, error=0.0073, AURC=0.0243. On the *mock*, the model's own confidence is a strong deferral signal (mock confidence ≈ softmax peak, near-oracle), so confidence edges FS here — EXPECTED and noted: the real test is whether FS beats confidence on real models where confidence is known to be miscalibrated/overconfident (Colab). Reported provisionally (pre-correction FS) per the calibration-ordering fix. Both gates certify the finite-sample bound with n_cal=1000.

- **[A] 2026-07-03 — Real dataset loaders verified against LIVE HF mirrors (CPU, no model).** Installed `datasets` 5.0.0. **VQA-RAD** (`flaviagiammarino/vqa-rad`): 451 test rows, real PIL images, parsed q/a; mirror has only image/question/answer (no modality/bbox) → modality text-tagged. **SLAKE** (`BoKelvin/SLAKE`): 100-sample probe → real modality labels {xray:61, ct:31, mri:8}, answer_type {OPEN:64, CLOSED:36}, English filter + closed yes/no detection working; images referenced by `img_name` path (need imgs.zip on Colab), **no per-QA bbox in this mirror**. **PathVQA** (`flaviagiammarino/path-vqa`): same schema as VQA-RAD (image/question/answer, all pathology) — parser identical, full 700MB image download deferred to Colab (not worth pulling to verify an identical parser on CPU). Loaders normalize all to the `Sample` schema; `load_dataset({"name": ...})` dispatch confirmed.

- **[A] 2026-07-03 — Signal B IoU validation source corrected.** Neither public mirror (VQA-RAD/SLAKE) carries per-QA bounding boxes inline, so real-data Signal B IoU-vs-GT is validated on the **synthetic** data (exact GT regions: mean IoU grounded 0.366 vs ungrounded 0.183, AUROC 0.739) and, on real SLAKE, only once the separately-distributed segmentation masks are wired (helper `bbox_to_region` ready; logged in BLOCKERS.md). Per review fix #3, real-data Signal B is therefore reported as *unvalidated/exploratory* until masks land — stated explicitly rather than implying grounding was verified on real images.

- **[A] 2026-07-03 — GPU-handoff orchestration validated on CPU (mock models, synthetic data).** `run_real.py` end-to-end: config-override → baselines → blind test → full FMR → figures, writing to `outputs/real/<dataset>/`. Confirmed working with mock_reasoner/mock_plain (acc 0.855, blind_gap 0.520, FS AUROC 0.881, all 4 figures produced). The temp/mock `outputs/real/` dir was then deleted (not committed) so `outputs/real/` holds only genuine GPU results pushed from Colab. Notebook `colab_real_pipeline.ipynb` written + JSON-validated.

- **[A] 2026-07-03 — Stage 6 full benchmark (mock, α=0.05, δ=0.05, two base models).** `run_fmr_full.py` runs the whole pipeline with correction wired in via a guarded import (Instance B's `correct_sample`/`CorrectionResult`; identity fallback when not on this branch → `correction_present: False` now, lights up at merge).
  - **Incremental-fusion ablation (AUROC vs grounding label):** mock_reasoner A=0.819 → A+B=0.821 → A+B+C=**0.870** (Signal C is the big lift here); mock_reasoner_b A=0.838 → 0.837 → 0.837 (fusion flat — a genuine, honest finding that fusion benefit is base-model-dependent, not universal).
  - **Model-agnosticism:** deployed post-correction FS gate is feasible AND the empirical guarantee holds on BOTH bases — mock_reasoner cov=0.581 err=0.019≤0.05 ✓; mock_reasoner_b cov=0.385 err=0.026≤0.05 ✓. FMR is not tuned to one base.
  - **Calibration ordering (review fix #4) implemented correctly:** the deployed gate calibrates on the *fused* FS **recomputed on the corrected output** (A=post-correction counterfactual from Instance B's rescore, B=coherence of the corrected chain, C=reused pre-correction consistency) — NOT Instance B's Signal-A-only `fs_after`, and NOT the raw pre-correction FS. Both `fs_post_correction` (deployed) and `fs_pre_correction` (ablation contrast) are reported. On the mock these coincide because correction is identity; the split becomes meaningful once Instance B's module merges.
  - Adapter signature verified byte-for-byte against `origin/instance-b:correction/pipeline.py` — drops in with zero changes at merge.
- **[A] 2026-07-03 — Test suite now 26/26** (added `test_full_benchmark.py`: Stage-6 orchestration smoke test over both base models — validation AUROCs sane, identity correction no-ops, deployed guarantee holds).

- **[A] 2026-07-03 — Stage 3/5 robustness & sensitivity ablations (mock; the headline components get the deepest treatment per review fix #1).** `run_ablations.py`:
  - **FS fusion-weight sensitivity** (full (a,b,c) simplex, step 0.1, n=1500): AUROC ranges **0.737–0.865, mean 0.827 ± 0.025**. FS quality does not hinge on a lucky weighting; best hand-weighting {a:0.3,b:0.4,c:0.3}=0.865. The envelope max (0.865) is the concrete number Instance B's learned verifier must beat.
  - **Signal-B grid sensitivity:** AUROC {g2:0.687, g3:0.732, g4:0.782, g6:0.789, g8:0.773} — grounding signal is present at every resolution (rises then plateaus), so it is NOT a grid-size artifact; g4–g6 is the sweet spot.
  - **Seed stability** (5 draws): signal_a 0.824±0.017, signal_b 0.747±0.004, signal_c 0.759±0.017, **fs 0.878±0.011** — highly stable across independent synthetic worlds.
  - **Abstention power (quantified):** min calibration size to certify each α — α=0.02→1500, **α=0.05→500**, α=0.10→500, α=0.15→200, α=0.20→100. Precise version of the earlier claim: tighter guarantees need more calibration data; on this cleaner synthetic world α=0.05 certifies at cal≈500 (the earlier cal=200 infeasibility was the smaller/noisier n=800 world). This is the honest, quantitative statement for the thesis.
  - Figures fig7 (weight envelope) + fig8 (power curve). Test suite now **31/31**.

- **[A] 2026-07-03 — Headline replication verdict wired into the blind test (review fix #2, made auto-evaluable).** `run_blind_test.py` now emits a `replication` block: the reasoning model's grounding-drift slope, `within_model_decay`, reasoning-vs-non-reasoning final-step comparison, and a boolean `replicated` + note. On the mock: **REPLICATED, drift slope −0.0326** (grounding decays s0=0.321→s3=0.218). Critically, on real Colab data this will *automatically* report non-replication if the effect doesn't hold — so the framing follows the data instead of being forced. Test suite **34/34** (added `test_blind_test.py` incl. a negative-case test asserting the verdict says "NOT replicated" when grounding rises).

- **[A] 2026-07-03 — Frontend deliverable: static FMR dashboard (`fmr/dashboard/`).** Built a zero-dependency, single-page dashboard (hand-rolled SVG charts — no CDN/build step) that reads a generated `data.js` bundle, so it runs straight from `file://` or any static host. Sections: Overview (stat cards), **The Diagnosis** (grounding-drift line chart + blind-test bars + REPLICATION verdict banner), **Measurement** (per-signal AUROC bars + grounded-vs-ungrounded separation histogram with A/B/C/FS toggle), **Safety Layer** (risk–coverage curve FS-vs-confidence-vs-singles with the calibrated operating point + a distribution-free-guarantee card + per-modality bars), **Case Explorer** (300 cases, filter by answered/abstained/grounded, per-case reasoning chain with per-step FS + signal bars + ANSWER/ABSTAIN decision), **Robustness** (incremental fusion across models, weight-sensitivity envelope, grid sensitivity, conformal power). Verified in a headless browser: 10 charts render with real shapes, explorer interaction works (case→detail with decision+steps), CSS applied (teal gradient topbar, styled cards), no console errors. A **MOCK/REAL source picker** switches datasets; `run_real.py` rebuilds+pushes `data.js` each stage so the hosted dashboard auto-tracks real results. Added `make_dashboard.py`; added additive `question`/`gt_answer`/`steps_text` record fields (verifier contract stays additive). 34/34 tests still pass.

- **[A] 2026-07-03 — First real Colab run: partial success + two bugs diagnosed & fixed.** MedVLM-R1 loaded and ran VQA-RAD baselines (acc reported), but: **(1) OOM** on the 14.5 GB T4 during Qwen2.5-VL's *vision encoder* (`get_image_features` → SDPA, 678 MB single alloc) — root cause is **image resolution**, not model count: VQA-RAD scans are ~1024px and Qwen2.5-VL tokenizes by pixels, so the vision attention (O(tokens²)) blows up. **(2) MedVLM-R1 acc=0.150** — a parsing bug: R1 emits `<think>…</think><answer>X</answer>`, but the parser only looked for `Answer:`, so answers weren't extracted. **Fixes (pushed):** cap longest image side to 512px in `hf_vlm._load_image` + set processor `max_pixels` (the decisive OOM fix — slashes vision tokens); load fp16 + `low_cpu_mem_usage`; per-candidate `empty_cache` in `_score_candidates`; explicit `HFVLM.unload()` called between models in all three stage scripts; notebook sets `PYTORCH_CUDA_ALLOC_CONF=expandable_segments:True` before importing torch. Robust `_parse_answer` now handles `<answer>` tags / `<think>` stripping / whole-text choice fallback — validated 6/6 on real R1-style strings (CPU). 34/34 tests still pass. Re-run the notebook; the smoke run should now complete and push.

---

## ⎯⎯ Merged from instance-b (Instance B's log) ⎯⎯

Every entry: `[A]`/`[B]` tag · date · what ran · actual numbers · verdict.
Never rewrite or delete an existing entry.

---

### [B] 2026-07-03 — Stage 4 correction module: unit tests + full mock verification

**Shared-foundation fix first:** the initial commit could not `import fmr` at all
(circular import `types → data.regions → data/__init__ → synthetic → types`).
Fixed minimally in `types.py` (`Region` import moved under `TYPE_CHECKING`); logged
in DECISIONS.md [B]. This unblocks *everything*, Instance A's code included.

**Unit tests:** `fmr/tests/test_correction.py` — **12 passed** (1.05s). Covers VCD
math (prior cancels / evidence amplified / no-op when distributions match /
plausibility mask blocks implausible promotion), clue-tracing grounded-vs-blind
separation and near-GT region recovery, verify-revise step dropping + no-mutation +
conservative answer policy, rescore output-shape parity with Signal A, and pipeline
selective application / prior-rescue / abstention routing / second-VLM factory.

**Full run:** `scripts/run_correction.py --model both --n 400` (synthetic, seed 7).
Two mock backends, two deliberately different failure modes.

**MockVLM `mock-reasoner` (image-blind pathology):** 265/400 flagged (FS<0.5).
- *Fixable (grounded latent, n=61):* acc 1.00→1.00; **FS_after mean 0.54; 91.8%
  recover above the abstention gate** — i.e. grounded chains flagged only for
  reasoning-drift are re-grounded so they need not be deferred. This is the
  "correction shrinks the abstain set" story.
- *Image-blind (latent, n=204):* acc 0.539→0.529 (flat), FS_after 0.044, **96.1%
  stay below the gate → routed to abstention.** Correction correctly refuses to
  fabricate confidence when there is no image signal.
- *Regression (correction force-applied to 135 unflagged):* **0 correct answers
  broken**, acc 1.00→1.00.

**PriorHeavyMockVLM `mock-prior-heavy` (prior-dominated pathology — VCD's target):**
393/400 flagged.
- *Fixable (grounded latent, n=189):* **acc 0.534→0.868 (+33.3 pts)** — VCD flips
  prior-dominated wrong answers to the image-grounded truth. Of the 66 answers it
  changed, the rescue is decisive (see audit rows syn-00001/2/4/7: prior answer →
  GT answer, FS 0.02→~0.60).
- *Image-blind (latent, n=204):* acc 0.539→0.534 (flat), FS_after 0.036, **98.5%
  stay below the gate → abstention.**
- *Regression (forced on 7 unflagged):* **0 correct answers broken.**

**Verdict:** PASS. Both the improvement claim (prior-dominated cases rescued,
+33 pts accuracy on the fixable subset) and the two non-regression guarantees
(image-blind cases left to abstention; well-grounded cases never corrupted) hold.
The fixable/must-abstain split is exactly the framing required by external-review
fix #1: correction is the layer that *shrinks* what abstention must defer, not a
co-equal contribution. Artifacts: `fmr/results/correction_{summary,audit}_*.{json,jsonl}`.

### [B] 2026-07-03 — LLM-as-judge validation (required-fix #3)

Built `fmr/src/fmr/eval/judge.py` (HeuristicJudge + LLMJudge + agreement harness)
+ a hand-authored gold set `eval/gold_data.py` (N=44: 22 correct / 17 incorrect /
5 partial), stressing synonyms, negation/polarity flips, severity, containment,
and multi-finding partials.

**Heuristic judge vs gold, iterated (revise-and-recheck per fix #3):**
- v1 (string match + whole-string synonyms): 3-way acc 0.795, **κ 0.634**.
- v2 (token-level synonyms, number-word norm, multi-finding coverage): acc 0.909,
  **κ 0.836**.
- v3 (comma-robust multi-finding via cluster count; "names finding but omits
  detail"→partial): acc 0.955, binary 1.000, **κ 0.923**.
- v4 (exclude polarity/severity words from *finding* count; polarity-aware
  coverage): **acc 1.000, binary 1.000, κ 1.000.**

**Honesty caveat (stated for the thesis):** κ=1.0 is on a gold set I *both
authored and tuned against* — it is an upper bound on a hand-tuned rule, not a
field estimate. Two independent guards: (1) `tests/test_judge.py` includes 9
HELD-OUT probes never in the gold set (bleeding↔hemorrhage, broken↔fracture,
three↔3, held-out multi-finding partials, underspecified single findings) — all
pass, so the rules encode general clinical-text principles, not memorized rows;
(2) the real external check is the *independent* open-LLM judge on Colab
(`colab_judge_llm.ipynb`), scored against the same gold + against the heuristic.
Until that lands, downstream open-ended metrics use the heuristic as the
validated fallback and should treat the LLM judge as primary once its κ is in.

**Tests:** `tests/test_judge.py` 21 passed; full suite **33 passed** (0.74s).
Artifact: `fmr/results/judge_validation_heuristic.json`.

### [B] 2026-07-03 — Learned faithfulness verifier vs heuristic fusion (RQ5)

Built `fmr/src/fmr/training/` (signals → features → labels → verifier → dataset) +
`scripts/train_verifier.py`. Verifier = sklearn LogisticRegression (learned-linear)
or GradientBoosting (learned-nonlinear, regularized: depth 2, 150 trees, subsample
0.8, min_leaf 20), a **drop-in for `HeuristicFusion`** (identical `score(features)`
API; heuristic stays the guaranteed fallback per fix #4).

**Protocol.** Features from **two** backends (mock-reasoner + mock-prior-heavy) so
signals conflict. Trained on the **noisy counterfactual weak label** (no GT boxes;
weak-vs-true agreement ≈0.78 — genuinely weak). Evaluated vs the **true hidden
latent** on a held-out split **disjoint from the calibration split reserved for
Instance A** (train 200 samples ×2 backends = 400 rows; test 100 ×2 = 200 rows;
cal 100 untouched). Because real faithfulness signals are noisy (not the clean
latent a deterministic mock exposes), we sweep measurement noise σ.

**Result (AUROC vs true latent):**

| σ (noise) | per-signal A/B/C | heuristic | learned (logreg) | Δ learned−heur | oracle |
|-----------|------------------|-----------|------------------|----------------|--------|
| 0.00 | 0.99/0.99/0.71 | **0.998** | 0.987 | −0.012 | 1.000 |
| 0.15 | 0.78/0.99/0.64 | **0.987** | 0.978 | −0.009 | 1.000 |
| 0.30 | 0.73/0.99/0.59 | 0.928 | **0.965** | +0.037 | 1.000 |
| 0.45 | 0.66/0.97/0.57 | 0.839 | **0.940** | +0.101 | 1.000 |
| 0.60 | 0.62/0.93/0.55 | 0.756 | **0.909** | +0.153 | 0.999 |

**Reading it honestly.** With *clean* signals the fixed heuristic is already near
the ceiling and the learned head (trained on noisy weak labels) loses by ~0.01 —
reported, not hidden. The crossover is σ≈0.2; beyond it the learned fusion degrades
far more gracefully and the gap widens monotonically to +0.153. **Mechanism** (from
per-signal AUROC + logreg weights): noise corrupts Signal A (0.99→0.62) while
Signal B stays robust (0.99→0.93); the fixed 0.5 weight on A drags the heuristic
down, whereas the learned head re-weights toward B. The oracle (GBT on the true
latent) stays ≈1.0, confirming the information is still present — the heuristic just
can't extract it under noise. Since real signals are noisy, the realistic regime is
σ>0, where the learned verifier wins → **it ships as default at the headline σ=0.3
(0.965 vs 0.928), with the heuristic as fallback.** Held-out decision agreement
with the heuristic is 0.86 (not wildly divergent; the divergence is exactly the
re-weighting that helps).

**Caveat / dependency:** trained on stub signals computed in `training/signals.py`
(stand-in for Instance A's real Signal A/B/C from `faithfulness/score.py`, not on
disk yet). Must **retrain on real signals** once available — logged in DECISIONS.md
[B]. The noise sweep predicts the learned head helps whenever real signals are
moderately noisy (which they are).

**Tests:** `tests/test_verifier.py` 9 passed (incl. deterministic
learned>heuristic+0.05 under σ=0.5, save/load round-trip, weak-label-is-noisy).
Full suite **42 passed** (2.89s). Artifacts: `fmr/results/verifier_benchmark.json`,
`fmr/results/verifier_gbt.pkl(+.meta.json)`.

### [B] 2026-07-03 — Correction shrinks the abstain set (fix #1 quantified)

`scripts/correction_abstention_preview.py`: an *illustrative* selective-prediction
comparison (NOT the conformal gate — Instance A owns `abstention/`). Same threshold
sweep applied to two deferral signals: NAIVE = pre-correction FS + raw answer; FMR =
post-correction FS + corrected answer. 400 synthetic samples.

**Prior-dominated backend (`mock-prior-heavy`) — the headline:**
- overall accuracy 0.545 → **0.700** after correction.
- risk–coverage AUC (lower=better): naive **0.352 → FMR 0.128** (2.7× less risk
  under selective prediction).
- fraction answerable at **≥90%** retained accuracy: naive **9.3% → FMR 48.5%**
  (**5.2×**); at ≥95%: **4.8% → 43%** (≈9×).
- retained acc at 50% coverage: naive 0.56 → FMR 0.91.

**Image-blind backend (`mock-reasoner`) — the honest flip side:**
- accuracy 0.765 → 0.760 (flat); rc-AUC naive 0.065 vs FMR 0.076 (≈neutral,
  marginally worse). Correct behaviour: when there is no image evidence to recover,
  correction does not move the frontier — those cases stay deferred to the gate.
  Correction helps the abstention curve *only where evidence exists*, which is
  exactly its intended, narrow role.

**Takeaway:** this is the quantified statement of external-review fix #1 —
correction is supporting infrastructure that *shrinks what abstention must defer*
(5× more cases safely answerable on the fixable pathology), not a co-equal
contribution, and it is inert (not harmful) where nothing is fixable. Directly
motivates the calibration-ordering handoff (fix #2): the gate must calibrate on the
post-correction FS to capture this shifted frontier. Artifact:
`fmr/results/correction_abstention_preview.json`.

### [B] 2026-07-03 — Faithfulness-LoRA data construction (stretch; fit is GPU-only)

`fmr/src/fmr/training/faithfulness_lora.py`: the CPU-testable half of the RQ3
"can grounding be learned into the weights?" ablation. `build_self_distillation_set`
turns the correction module's verified-grounded outputs into (question, grounded
rationale, answer) targets — keeping only samples whose post-correction FS clears
the bar, so an ungrounded rationale is never distilled. `build_preference_pairs`
builds grounded-≻-ungrounded DPO pairs. The QLoRA fit itself is a GPU stub that
points to the handoff notebook.

**Verification (CPU):** `tests/test_faithfulness_lora.py` 4 passed —
(1) distill set keeps only FS≥bar targets, well-formed; (2) image-blind samples are
excluded (≤10% leak on the image-blind backend — we don't distill ungrounded
chains); (3) preference pairs genuinely contrast chosen(FS≥bar) vs rejected(FS≤0.2);
(4) the training entry-point raises on CPU (GPU-only). Full suite **46 passed**
(4.35s). GPU run packaged: `fmr/notebooks/colab_faithfulness_lora.ipynb` (frozen
base vs LoRA held-out ablation; frozen stays default — fix #4).

---

### [B] 2026-07-03 — Instance-B scope status snapshot

Core + stretch of Instance B's scope are implemented, CPU-verified, committed, and
pushed to `origin/instance-b`:
- **Stage 4 correction** (VCD + clue-tracing + verify/revise + rescore + selective
  pipeline) — done, 12 tests, mock gains logged, ready for A's calibration (fix #2
  handoff posted).
- **Second base VLM** (`PriorHeavyMockVLM` + `SecondHFVLM` scaffold) — done.
- **LLM-judge + validation** (fix #3) — done, κ=1.0 on gold (caveated), 21 tests.
- **Learned verifier** (RQ5) — done, noise-sweep shows learned>heuristic for σ≳0.2,
  9 tests, ships-with-fallback.
- **Correction→abstention preview** (fix #1 quantified) — done.
- **Faithfulness-LoRA** (stretch) — data-construction done + tested; fit is a GPU
  handoff notebook.
- **5 GPU handoff notebooks/paths** ready on `instance-b` (correction-real,
  judge-llm, faithfulness-lora). **46 tests passing** total.

Open dependencies on Instance A (all flagged in DECISIONS.md [B], all with working
stubs so nothing is blocked): real Signals A/B/C from `faithfulness/score.py` (to
retrain the verifier on real data + feed the fused FS into the correction trigger),
and wiring the post-correction FS into the conformal gate.

### [B] 2026-07-03 — Integrated against Instance A's real interface (merge-ready)

Instance A published `faithfulness/score.py` on `master` with a documented
per-signal record schema built explicitly for this verifier. I integrated without
touching their files or my branch's standalone-ness:
- `training/adapter.py` — maps one A-record → verifier `FEATURE_KEYS`
  (`features_from_record`), + `frame_from_records`, + weak/true-label extractors.
  Prefers GT-based `iou_per_step`/`weak_labels` when present, falls back to
  `signal_b_per_step`/counterfactual-flip otherwise. Dict-only (no import of A's
  module). **Tests:** `tests/test_adapter.py` 8 passed, incl. an end-to-end train
  of a LearnedVerifier on real-schema records → AUROC>0.9 vs latent.
- `correction.post_correction_fs(...)` — injectable fused post-correction FS for
  the conformal gate (fix #2 upgraded): pass A's `attention_signal` + `fuse` and
  the sample's `signal_c` to get a fully-fused post-correction score; defaults
  mirror A's 0.4/0.3/0.3 weights. **Tests:** 2 added (default + injected-A path).

**Merge plan (one-line source swaps, no logic changes):**
1. verifier: `frame_from_records(score.score_dataset(vlm, samples))` → retrains on
   real Signals A/B/C.
2. correction trigger: `correct_sample(vlm, s, fs=record["fs"])` → uses A's fused FS.
3. gate: calibrate on `post_correction_fs(..., attention_fn=attention_signal,
   consistency_c=record["signal_c"], fuse_fn=score.fuse)["fs"]`.

Full suite now **56 passed** (4.90s).

### [B] 2026-07-03 — Per-component correction ablation (proposal Section 9)

`scripts/ablate_correction.py` decomposes correction into its three primitives on
the same flagged (low-FS) samples, so the gain is *attributed*, not just reported.
Rows add one component at a time; `verify_and_revise` gained an injectable
`supports` vector so the support *source* can be swapped (clue-tracing vs a
no-trace single-chain self-consistency baseline). 400 synthetic samples.

**`mock-prior-heavy` (VCD's target pathology; flagged=393, holdout=7):**

| config | acc | step_support | keep_frac | fs_after | regr_broken |
|--------|-----|--------------|-----------|----------|-------------|
| baseline | 0.537 | 0.260 | 1.000 | 0.017 | 0 |
| +VCD | **0.695** | 0.260 | 1.000 | 0.157 | 0 |
| +Verify(noclue) | 0.537 | **0.529** | 0.290 | 0.017 | 0 |
| +Verify+Clue | 0.537 | **0.551** | 0.298 | 0.017 | 0 |
| Full | **0.695** | **0.551** | 0.298 | 0.157 | 0 |

**`mock-reasoner` (image-blind pathology; flagged=265, holdout=135):**

| config | acc | step_support | keep_frac | fs_after | regr_broken |
|--------|-----|--------------|-----------|----------|-------------|
| baseline | 0.645 | 0.186 | 1.000 | 0.093 | 0 |
| +VCD | 0.638 | 0.186 | 1.000 | 0.158 | 0 |
| +Verify(noclue) | 0.645 | 0.422 | 0.250 | 0.093 | 0 |
| +Verify+Clue | 0.645 | 0.385 | 0.279 | 0.093 | 0 |
| Full | 0.638 | 0.385 | 0.279 | 0.158 | 0 |

**Attribution (the point of the table):**
- **VCD owns answer accuracy:** +15.8 pts on the prior-dominated pathology
  (0.537→0.695), ≈0 (−0.007) on image-blind — nothing to recover when no image
  evidence exists, and it never touches the rationale (step_support flat).
- **Verify-revise owns rationale faithfulness:** step-support rate ~doubles
  (0.260→0.529 prior; 0.186→0.422 mock) by dropping ungrounded steps to
  keep_frac≈0.29. Answer unchanged (it only edits the rationale).
- **Clue-tracing improves the support source** on the fixable pathology
  (0.529→0.551) — modest but real vs the no-trace baseline. Honest wrinkle: on the
  image-blind model it is ≈neutral/slightly worse (0.422→0.385), because when
  almost no step is grounded, multi-chain tracing scatters and the single-chain
  self-consistency baseline is no worse — consistent with clue-tracing helping only
  where evidence exists.
- **Safety:** 0 correct answers broken in *every* config on the well-grounded
  holdout (135 for mock; prior holdout is only 7 because that model is low-FS
  almost everywhere — the mock's 135 is the stronger safety signal).

**Verification:** `verify_and_revise` `supports`-injection unit test added; full
suite **57 passed** (3.76s). Artifact: `fmr/results/correction_ablation.json`.

### [B] 2026-07-03 — REAL-MODEL Colab runs: results + rectifications

The user ran the three GPU notebooks. Outcomes and fixes:

**1. LLM-judge independent validation — ✅ SUCCESS.**
`colab_judge_llm.ipynb` scored the N=44 gold set with an independent open LLM
(Qwen2.5-7B-Instruct): **3-way accuracy 0.864, binary (correct-vs-not) 0.955,
Cohen's κ = 0.758**, all 44 verdicts from the LLM (0 fallbacks). This is the
external check the plan required: κ=0.758 is "substantial" agreement (>0.6), so the
judge is trustworthy for Stage-6 open-ended scoring. It also re-frames the
heuristic's κ=1.0 correctly — the heuristic was *tuned* to the gold set (upper
bound); an *independent* LLM lands at 0.758, which is the honest field-level number
to report. Artifact: `fmr/results/judge_llm_validation.json`. **No fix needed.**

**2. Real-model correction (Qwen2.5-VL-3B, VQA-RAD closed, N=40) — ⚠️ ran, but
correction slightly HURT accuracy; rectified.**
Result: acc 0.625→0.575 (flagged 0.686→0.629), only 4 answers changed, fs
0.202→0.265. This is the *known* VCD failure mode: on yes/no questions the model's
language prior is often *correct*, and VCD suppresses the prior-aligned answer even
when it was right. 40 samples / 4 changes is within noise, but the direction is
real. **Root cause:** the default `vcd_margin=0.25` (tuned on the clean mock) is too
permissive for a real model's noisier distributions. **Fix (notebook v2):** replaced
the single run with a *cached* `vcd_margin` trade-off sweep
{0, 0.25, 0.5, 1, 2, ∞} — one generation pass, margins applied cheaply — reporting
`acc_after` and `fs_after` at each, and auto-selecting the safe operating point
(smallest margin with `acc_after ≥ acc_before`; `margin=∞` provably returns to
baseline). This is the proposal-prescribed "report the trade-off curve, not a single
point." Sweep loop validated on CPU/mock (monotonic: mock prior-heavy 0.467→0.700 at
low margin, →0.467 at ∞). **The honest takeaway to report: on real closed-set VQA,
VCD helps only above a margin threshold; below it, the right-prior cases are hurt.**

**3. Second model MedGemma — ❌ 403 gated (not a code error); rectified.**
`google/medgemma-4b-it` returned "not in the authorized list" (access request
pending/denied — see BLOCKERS). **Fix (notebook v2):** the cross-model check now uses
the **ungated** `Qwen/Qwen2-VL-2B-Instruct` (runs the same adapter with the
conservative `vcd_margin=1.0`); MedGemma remains an optional block that runs only if
access is granted.

**4. Faithfulness-LoRA — ❌ no output (silent failure); rectified.**
No results file was pushed. Two likely causes, both fixed in v2: (a) v1 built the
distill set by running full correction on **120** real-model samples (~2 h → probable
Colab timeout) — v2 uses 30 samples, `n_probes=2`; (b) the distill selector used the
absolute `keep_threshold=0.5`, but real-model fs≈0.26, so it would have selected
**zero** targets — v2 selects the **top half by `fs_after` (data-driven median)**,
verified on CPU to yield 15/30 targets regardless of fs scale. Also hardened the
multimodal `Trainer` (`remove_unused_columns=False` — the classic silent killer that
strips image/label columns; label masking of pad+image tokens; `use_cache=False` +
gradient checkpointing) and wrapped train+eval so it **always writes a diagnostic
JSON** (with traceback on failure) — no more silent no-output runs.

All three notebooks also gained the `hf_hub>=0.34` strict-config patch (coerces bool
config fields None→True) that the base-model loads were crashing on. Notebooks
rebuilt, nbformat-valid; sweep + distill logic validated on CPU. **Ready to re-run.**

# RESULTS_LOG.md — running experimental log (append-only)

Every entry: `[A]`/`[B]` tag · date · what ran · actual numbers · verdict.
Never rewrite or delete an existing entry.

---


### [B] 2026-07-03 — FULL PROJECT INTEGRATION (merge master → instance-b) + real-signal RQ5

**Merged Instance A's half into instance-b** so the whole FMR pipeline exists in one
tree: A's Signals A/B/C, FS fusion (`score.py`), conformal abstention, real loaders,
HF backend, `run_fmr_full` end-to-end harness, dashboard/figures — together with B's
correction, learned verifier, judge, second VLM, LoRA. Conflicts resolved (types.py
shared fix; hf_vlm→A's; logs concatenated). **Full combined suite: 93 passed.**

**End-to-end pipeline runs (`scripts/run_fmr_full.py`, graded mock):** signals →
fusion → **B's correction** → post-correction FS → conformal gate, all connected.
- incremental fusion AUROC (mock_reasoner): A=0.819 → AB=0.821 → **ABC=0.870**.
- **correction applied=706, acc 0.863→0.875 (+1.2pts), meanFS 0.399→0.545** — the real
  correction path (not identity) runs and helps.
- A's harness already wired B's `correct_sample(vlm, s, fs=record["fs"],
  original=record["output"])` and calibrates the gate on the *post-correction* fused
  FS — exactly the fix-#2 ordering I handed off. Integration confirmed both ways.

**RQ5 on REAL signals — POSITIVE (`train_verifier.py --source real`).** Verifier trained
on A's real `score_dataset` output via `training/adapter.py`, 400 samples × 2 backends:
- heuristic fusion AUROC **0.768**; learned **GBT (weak labels) 0.816 (+0.048)**, logreg
  0.801 (+0.033) → **LEARNED VERIFIER BEATS THE HEURISTIC on the real pipeline**, no
  measurement noise needed. Oracle (true-label) 0.951 (headroom); weak-vs-true 0.77.
- *Why it wins here but not on the stub:* A's real signals + A's IoU-based `weak_labels`
  give the learned fusion real cross-signal structure the fixed weighting misses. **The
  real-signal result is the headline** (`fmr/results/verifier_benchmark_real.json`).

**Gate-feasibility finding (for [A]):** the deployed (post-correction FS) conformal gate
is **infeasible at α=0.05** (correction inflates FS 0.40→0.55, decoupling FS from
correctness at the strictest target) but **feasible at α≥0.10**; pre-correction gate is
feasible at 0.05. Not a bug — a target choice; report the risk–coverage frontier and use
α≈0.10 as headline. Logged in DECISIONS [B].

**Refreshed graded-mock artifacts:** correction ablation — prior-heavy VCD +15.3pts
(0.537→0.690), verify-revise ~doubles step-support (0.258→0.557), 0 correct broken;
abstention preview — prior rc-AUC 0.351→0.132, answerable@≥90% acc 8.5%→48.3% (5.7×).

---


- **[A] 2026-07-04 — PART 1 dashboard-data verification/fixes (before UI overhaul).** Investigated all four flagged issues on the real data (VQA-RAD n=20, PathVQA n=50, both pushed from Colab).
  - **Issue 2 (Signal B "AUROC 0.671" vs "constant" claim) — ROOT-CAUSED & FIXED.** The 0.671 was NOT an AUROC; it was Signal B's **AURC** (area under risk-coverage) in `abstention_baselines.json` for real:vqa_rad. Real fmr_results.validation has NO auroc keys at all (no grounding labels on real data). Confirmed Signal B is genuinely **constant** on real (n_distinct=1, all 0.5 — attention→region still stubbed); Signal C also constant (all 1.0). The non-0.5 AURC was a **tie-order artifact**: `risk_coverage_curve` used `np.argsort(-scores)` which breaks all-tied scores by arbitrary index order, fabricating a meaningful-looking curve for a constant signal. **Fix:** made `risk_coverage_curve`/`coverage_at_risk`/`risk_at_coverage` **tie-aware** (`_tie_aware_expected_error`: replace each sample's correctness with its equal-score group mean). A constant signal now yields flat risk = base error at every coverage (AURC = base_err×(1−1/n)) and a `degenerate:true` flag. 2 new tests (constant→non-discriminative; AURC order-independent). 101 tests pass.
  - **Issue 3 (abstention table 0.750 everywhere) — VERIFIED CORRECT + made honest.** Confirmed each method computes its OWN distinct scores (not a shared/cached array): signal_a/fs/confidence have n_distinct=20; the flat 0.750 is genuinely correct at n=20/base-acc-0.25 (no trigger can concentrate the 5 correct answers). BUT the per-trigger AURC *ranking* was spuriously crowning constant signals (self_consistency/RadFlag/Signal B, all degenerate) as "best". **Fix:** ranking now EXCLUDES degenerate triggers; on real:vqa_rad, among discriminating triggers **FS is best (AURC 0.749)**; degenerate ones listed separately. Recomputed real fmr_results.abstention tie-aware (`recompute_real_abstention.py`).
  - **Issue 4 ("unknown" modality) — DIAGNOSED (mirror limitation, not a bug).** `flaviagiammarino/vqa-rad` ships only image/question/answer — NO modality field; modality is text-guessed and 63/80 VQA-RAD questions ("are the kidneys normal?") don't name the modality → "unknown". This is honest, not a parse error. **SLAKE parses REAL modality labels correctly** (ct/mri/xray, verified in slake baselines per_modality). Consequence: the modality-breadth story leans on SLAKE (real labels); the dashboard will relabel VQA-RAD "unknown" as "modality unspecified (mirror lacks metadata)" rather than implying a bucket.
  - **Issue 1 (Robustness empty on Real) — full_benchmark/ablations are inherently synthetic-fixture (run on `build_synthetic_dataset`), so there are no "real ablations" to run; the honest fix is a dashboard fallback showing the Mock ablations with a clear "Mock (synthetic) — real ablations not applicable" label.** Implemented in the Part-2 rebuild (Robustness tab always shows mock ablations, badged mock, never four blank boxes).
