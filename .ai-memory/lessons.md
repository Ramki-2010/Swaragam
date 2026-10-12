# Swarag — Lessons Learned

## Lesson Log

### L-001: Silent Exception Swallowing Hides Critical Bugs
- **Date**: 2026-02-15
- **Context**: `recognize_raga_v12.py` wraps the entire recognition in
  `except Exception` and returns UNKNOWN. When `MIN_STABLE_FRAMES` was
  missing, every call crashed with `NameError` — but the error was never
  visible. Every file silently returned UNKNOWN.
- **Rule**: Never use bare `except Exception` without at minimum logging
  the traceback. If a function silently degrades, add at least
  `print(f"ERROR: {e}")` or `traceback.print_exc()` so failures are visible.
- **Impact**: This bug could have gone undetected for weeks.

### L-002: Constants Must Be Synchronized Across Pipeline Scripts
- **Date**: 2026-02-15
- **Context**: `aggregate_all_v12.py` defines `MIN_STABLE_FRAMES=5`,
  `ALPHA=0.5`, `EPS=1e-8`. These same constants must appear in
  `recognize_raga_v12.py` because inference must match training exactly.
- **Rule**: Any constant used in both aggregation and recognition must
  be defined in both scripts with identical values. Consider extracting
  shared constants into a `config.py` module in the future.
- **Impact**: Mismatch between training and inference features produces
  garbage similarity scores.

### L-003: Test Scripts Should Use Production Thresholds
- **Date**: 2026-02-15
- **Context**: `test_recognize_fix.py` uses relaxed thresholds
  (MARGIN_STRICT=0.003, MIN_MARGIN_FINAL=0.0005) while production uses
  (MARGIN_STRICT=0.05, MIN_MARGIN_FINAL=0.01). This makes test results
  misleading — files that pass the test would fail in production.
- **Rule**: Test scripts should either (a) use production thresholds, or
  (b) clearly report raw margins and let the human judge. Avoid different
  thresholds that give false confidence.

### L-004: Shankarabharanam Is the Default Attractor
- **Date**: 2026-02-15
- **Context**: Any raga not in the training set gets classified as
  Shankarabharanam because its PCD is the most "generic" (major-scale-like).
  This is the "Shankarabharanam sink" problem.
- **Rule**: With only 3 trained ragas, the system cannot reject unknown
  ragas reliably. Margin thresholds alone are insufficient — an absolute
  score floor or OOD detection mechanism is needed.
- **Impact**: High false positive rate on out-of-distribution audio.

### L-005: Score Compression Makes Margins Unreliable
- **Date**: 2026-02-15
- **Context**: All scores from `test_recognize_fix.py` are negative
  (range -0.114 to -0.143). The genericness penalty dominates, pushing
  all scores below zero and compressing the effective margin range.
  A margin of 0.005 looks "large" in percentage terms but is actually
  tiny in absolute score space.
- **Rule**: When tuning margin thresholds, always inspect the actual
  score range first. If scores span only 0.03 total, a margin threshold
  of 0.05 will reject everything.

### L-006: Dyad Fix Is Necessary But Not Sufficient
- **Date**: 2026-02-15
- **Context**: Adding stable-region detection + Laplace smoothing to
  inference dyads (matching aggregation) correctly identifies Bhairavi.
  But it does not solve Shankarabharanam sink or Kalyani compression.
- **Rule**: The dyad fix is a prerequisite for correct operation but
  additional work is needed: OOD detection, genericness tuning, and
  potentially phrase-level features for sibling raga separation.

### L-007: Always Activate Virtual Environment Before Running Scripts
- **Date**: 2026-02-15
- **Context**: Running `python test_recognize_fix.py` without activating
  `my_virtual_env_swarag` fails with `ModuleNotFoundError: numpy`.
- **Rule**: Always activate the venv first:
  ```powershell
  Set-Location D:\Swaragam\scripts
  .\my_virtual_env_swarag\Scripts\Activate.ps1
  python <script>.py
  ```
  Or use the full path: `.\my_virtual_env_swarag\Scripts\python.exe <script>.py`

### L-008: PowerShell Does Not Support && Operator
- **Date**: 2026-02-15
- **Context**: `cd scripts && python test.py` fails in PowerShell.
- **Rule**: Use semicolon (`;`) as statement separator in PowerShell,
  or use `Set-Location` instead of `cd`.

### L-009: Adding More Ragas Reduces OOD Problem But Does Not Eliminate It
- **Date**: 2026-02-15
- **Context**: Asked whether adding more ragas to training would fix
  BUG-002 (Shankarabharanam sink). Analysis showed that more ragas
  reduce the "unknown space" (fewer inputs are truly OOD), but there
  will ALWAYS be audio that doesn't belong to any trained raga.
- **Rule**: Adding data is a PRIORITY 5 fix. It reduces the problem
  but does not eliminate it. An absolute score floor (OOD detector)
  is needed regardless of how many ragas are trained. Always fix code
  before adding data. See workflow.md Section 4 (Decision Tree).
- **Impact**: Without this understanding, one could spend weeks
  collecting data when a 5-line code fix would solve the root cause.

### L-010: Fix Priority Order Prevents Wasted Effort
- **Date**: 2026-02-15
- **Context**: With 3 active bugs (missing constants, OOD sink, score
  compression), it was tempting to jump to the most interesting problem.
  But fixing BUG-002 or BUG-003 is pointless if BUG-001 (missing
  constants) means the production script silently crashes on every call.
- **Rule**: Always follow the fix priority order:
  1. BLOCKING (crashes, silent failures)
  2. DATA INTEGRITY (feature mismatches)
  3. SCORING (weight tuning)
  4. ARCHITECTURAL (OOD detection)
  5. DATASET (adding ragas)
  Never skip a higher priority to work on a lower one.
- **Impact**: Without this discipline, you fix the roof while the
  foundation is cracked.

### L-011: Sandbox-First Prevents Production Breakage
- **Date**: 2026-02-16
- **Context**: Architectural audit of recognize_raga_v12.py revealed
  7 findings, some requiring significant changes. Applying them directly
  to production could introduce regressions. The existing test_recognize_fix.py
  already proved this pattern: it validated the dyad fix safely before
  production was touched.
- **Rule**: Never edit production scripts directly. Always:
  1. Apply the fix in a test_*.py sandbox script
  2. Run it against test audio
  3. Compare before vs after
  4. Only apply to production if results are BETTER
  See agent_spec.md RULE 6 and workflow.md Section 5.
- **Impact**: One bad edit to recognize_raga_v12.py could silently
  break all recognition (as BUG-001 demonstrated).

### L-012: A Penalty That Doesn't Change Ranking Is Useless
- **Date**: 2026-02-16
- **Context**: Architectural audit found that `compute_genericness(pcd)`
  is computed from the test PCD only, producing the same value for every
  raga. Subtracting the same constant from all scores does not change
  ranking or margin — it only shifts absolute values.
- **Rule**: Any scoring component that does not vary across candidates
  is mathematically inert for ranking. Before adding a penalty or bonus,
  ask: "Does this value differ between raga A and raga B?" If not, it
  cannot help differentiate them.
- **Impact**: The genericness penalty was believed to help suppress
  Shankarabharanam. In reality it compresses all scores equally and
  contributes to BUG-003 and BUG-006.

### L-013: Document Architecture Says JSD, Code Uses Dot-Product
- **Date**: 2026-02-16
- **Context**: `docs/ARCHITECTURE.md` says scoring uses Jensen-Shannon
  divergence. `recognize_raga_v12.py` actually uses `np.dot()` (dot-product
  similarity). These are fundamentally different metrics.
- **Rule**: When refactoring scoring, always check what the documentation
  says and update EITHER the docs or the code to match. Never let them
  drift apart.
- **Impact**: A new contributor reading the docs would expect JSD-based
  scoring and be confused by the actual implementation.

### L-014: Multi-Agent Is an On-Demand Expert, Not a Routine Step
- **Date**: 2026-02-16
- **Context**: Initially integrated the 5-agent analysis as a mandatory
  Step 2 in every development loop. The founder correctly pointed out
  this wastes resources, time and tokens on simple tasks. The multi-agent
  should only be called for genuinely complex cross-domain problems.
- **Rule**: The multi-agent team is a SPECIALIST TOOL. Keep it on-demand.
  The AI should SUGGEST it when stuck ("Want me to run /analyze-swarag?"),
  but never run it automatically. Simple fixes don't need 5 experts.
- **Impact**: Without this restraint, every missing-constant fix would
  burn tokens on 5 expert analyses that add zero value.

### L-015: No Shortcutting Sandbox-First, Even for Obvious Fixes
- **Date**: 2026-02-16
- **Context**: BUG-001 (missing constants) was applied directly to
  production because the sandbox had validated it in a prior session.
  But the proper flow is: local sandbox fix -> run -> compare -> THEN
  push to production. Skipping steps erodes discipline.
- **Rule**: Always follow the full sandbox flow. Even if the fix is
  "just 3 constants," run the sandbox, capture output, confirm results
  match expectations, THEN apply to production. No shortcuts.
- **Impact**: The one time you skip, that's the time it breaks.

### L-016: Genericness From Model PCD Makes Things Worse
- **Date**: 2026-02-16
- **Context**: BUG-004 fix attempt — moved genericness computation from
  test PCD to model PCD. Expected Shankarabharanam to get penalized most.
  Instead, Shankarabharanam had the LOWEST entropy (3.248), meaning it
  got the SMALLEST penalty. Result: Shankarabharanam became even more
  dominant. Kalyani ranking flipped from #1 to #2. Bhairavi margin shrunk.
- **Rule**: Before implementing a penalty fix, inspect the actual data
  first. The assumption "Shankarabharanam has the most generic PCD" was
  wrong — its trained PCD is actually the most concentrated. Model
  entropy values are too close (3.25-3.29) to differentiate meaningfully.
- **Impact**: Without sandbox testing, this fix would have silently
  made production results worse. Sandbox-first workflow saved us.

### L-017: Escalation (Dyad-Heavy) Hurts When Training Data Is Thin
- **Date**: 2026-02-16
- **Context**: test_dyad_weights.py showed that escalation (0.3/0.7)
  crushes Kalyani's margin from 0.001131 to 0.000227 — a 5x degradation.
  Dyad-only (0.0/1.0) flipped the ranking entirely (Shankarabharanam #1).
  With only 6 clips per raga, dyad matrices are too noisy to carry
  more weight than PCD.
- **Rule**: Don't increase dyad weight until training data is sufficient
  (15-20 clips minimum). The dyads need stable averages to be
  discriminative. With thin data, PCD is the more reliable signal.
- **Impact**: The escalation path actively harms Kalyani recognition.
  Logged as BUG-007.

### L-018: Baseline Weights (0.6/0.4) Are Best With Current Data
- **Date**: 2026-02-16
- **Context**: test_dyad_weights.py tested 3 weight configs:
  Baseline (0.6/0.4), Dyad-heavy (0.3/0.7), Dyad-only (0.0/1.0).
  Baseline gave the best margins for BOTH trained ragas simultaneously.
  Bhairavi: 0.005664 (baseline) vs 0.002954 (dyad-heavy) vs 0.000245 (dyad-only).
  Kalyani: 0.001131 (baseline) vs 0.000227 (dyad-heavy) vs WRONG (dyad-only).
- **Rule**: Don't tune weights until the underlying models are solid.
  Weight tuning on noisy models produces unreliable conclusions.
  Get data right first, then re-evaluate weights.

### L-019: Get Data Before Tuning Code
- **Date**: 2026-02-16
- **Context**: Multiple code fixes attempted (genericness from model PCD,
  genericness removal, dyad weight tuning) — none improved accuracy
  beyond the baseline. All 3 ragas have only 6-10 training clips.
  The MIR Researcher pointed out 6 clips is too thin for stable models.
- **Rule**: When accuracy is stuck and training data is thin, adding
  more data is more likely to help than code changes. Code tuning on
  noisy models is like adjusting a camera lens when the film is blurry.
  Priority: data first, code second.
- **Impact**: Prevents wasting cycles on code fixes that can't improve
  results until the foundation (training data) is solid.

### L-020: Instrument Contamination Affects Pitch Extraction
- **Date**: 2026-03-09
- **Context**: Saraga concert recordings contain violin, mridangam, and
  tambura alongside vocals. pYIN picks up violin pitches (same raga but
  different timbre/octave), adding noise to PCD and dyad matrices.
  168 Saraga tracks have multitrack stems; we extracted vocal-only for 8.
  Remaining 16 were processed with Demucs htdemucs for vocal isolation.
- **Rule**: Always use vocal-only audio for pitch-based raga recognition.
  Check for multitrack stems first (free, lossless). Use Demucs for
  mix-only recordings. Never feed full concert audio to pYIN.
- **Impact**: Cleaner features, OOD false positives eliminated.

### L-021: Duration Cap Has No Accuracy Cost But Massive Speed Gain
- **Date**: 2026-03-09
- **Context**: Old recognize_raga.py had MAX_DURATION_SEC=360 (6 min cap).
  v1.2 dropped it. Some Saraga recordings are 40-65 minutes long.
  Processing 13.2 hours of audio took hours. With the 6-min cap restored,
  extraction ran in minutes. A raga establishes identity in 3-5 minutes.
- **Rule**: Always cap audio duration at 6 minutes for both feature
  extraction and recognition. The PCD stabilizes within minutes.
  Beyond that is diminishing returns.
- **Impact**: 10x speedup with no accuracy loss.

### L-022: Adding Ragas Fixes OOD Better Than Code Changes
- **Date**: 2026-03-09
- **Context**: Expanding from 3 to 6 ragas eliminated the Shankarabharanam
  sink for OOD test files. Hamsadwani and Mohanam now return UNKNOWN
  instead of being misclassified. Multiple code fixes (genericness tuning,
  weight changes) failed to fix this. Adding ragas succeeded.
- **Rule**: When the model has too few ragas, OOD rejection is impossible
  because there are not enough candidates to create meaningful margins.
  Adding ragas crowds out the generic attractor. Data beats code.

### L-023: Laplace Smoothing ALPHA Must Scale With Matrix Size
- **Date**: 2026-03-10
- **Context**: Dyad matrices (36x36 = 1296 cells) had ALPHA=0.5.
  Total Laplace mass = 1296 * 0.5 = 648. Typical file has ~370 transitions.
  Signal ratio: 370/1018 = 36%. Noise dominated 64% of the matrix.
  Dyad similarities were ~0.001 for ALL ragas — essentially random.
  Chordia & Rae (2007) used 12x12 matrices (144 cells). With 144 cells,
  ALPHA=0.5 would add only 72 total — much more reasonable.
- **Rule**: ALPHA must be proportional to 1/(matrix_size). For 1296 cells,
  ALPHA=0.01 gives signal ratio 97%, and `diag_alpha.py`'s analytical model
  projected a discrimination ratio of 5.88x. That 5.88x is a simulated
  projection, not a measurement — it assumes fixed overlap constants
  (shared_cells=30, diff_cells=5) rather than reading real dyad matrices.
  The measured ratio on actual models is 1.73x (`sandbox_phase2_alpha.py`,
  see L-026 and the Impact line below); 1.73x is the canonical figure.
  General formula: ALPHA < (mean_transitions / matrix_cells) * 0.1.
- **Impact**: ALPHA=0.01 improved dyad discrimination from 1.24x to 1.73x,
  and overall accuracy from 61% to 64%.

### L-024: Outlier Clips Can Skew Entire Raga Models
- **Date**: 2026-03-10
- **Context**: Munnu Ravana (Thodi) had entropy 2.4 (vs 2.9-3.2 for others)
  and self-similarity 0.2022 (2x higher than any other clip). It was pulling
  the Thodi mean model toward its Sa-heavy profile. Koluvamaregatha had
  sim_to_mean=0.050 (lowest of all Thodi clips, vs 0.060-0.105 for others).
- **Rule**: Before aggregation, check intra-raga consistency:
  1. Pairwise dot-product between clips (should be >0.04)
  2. Similarity to mean (should be >0.06)
  3. Entropy should be within 0.5 of the raga median
  Outliers should be excluded (moved to excluded/ folder, not deleted).
- **Impact**: Removing 2 outliers from 7 Thodi clips improved Thodi
  self-recognition from HIGH=6 to HIGH=5 (with 0 wrong), and reduced
  overall wrongs from 20 to 18.

### L-025: PCD-Only Scoring Is a Valid Stabilization Step
- **Date**: 2026-03-10
- **Context**: When dyads were broken (ALPHA=0.5, all similarities ~0.001),
  temporarily setting DYAD_WEIGHT=0.0 doubled margins and stabilized
  classification. This exposed the real problem (Thodi sink) that was
  previously masked by dyad noise.
- **Rule**: When a feature channel is suspected broken, disable it
  temporarily and test PCD-only. If margins improve, the feature was
  actively hurting. Fix the feature before re-enabling.
  This is diagnostic, not permanent.
- **Impact**: PCD-only immediately revealed that dyads were compressing
  margins by ~40%, leading to the ALPHA fix.

### L-026: Dyad Discrimination Ratio Is the Key Metric for ALPHA Tuning
- **Date**: 2026-03-10
- **Context**: The discrimination ratio (self-similarity / mean-other-similarity)
  directly measures whether dyads can tell ragas apart.
  ALPHA=0.5: ratio 1.24x (useless). ALPHA=0.01: ratio 1.73x (useful).
  Diminishing returns below 0.01 (0.001 gives 1.75x, 0.0001 gives 1.75x).
- **Rule**: When tuning ALPHA, measure discrimination ratio, not raw
  similarity values. Target: >1.5x for useful dyads. >2x for strong dyads.
  Sweep: [0.5, 0.1, 0.01, 0.001] and pick the knee point.
- **Impact**: This metric gave clear evidence that ALPHA=0.01 was the
  right value, avoiding guesswork.

### L-027: Consensus Across Independent Analyses Validates the Plan
- **Date**: 2026-03-10
- **Context**: Three independent analyses (our multi-agent team, the user's
  own analysis, and Grok's analysis) all converged on the same 3-phase plan:
  Phase 1 (PCD-only), Phase 2 (ALPHA fix), Phase 3 (OOD hybrid).
  The user correctly noted this convergence IS the validation.
- **Rule**: When multiple independent analyses agree, the confidence in
  the plan is high. Don't keep searching for alternatives — execute.
  Convergence from different perspectives is stronger evidence than
  any single deep analysis.
- **Impact**: Avoided analysis paralysis. Moved to execution immediately.
### L-028: Vocal Isolation Is Not Optional for Recognition
- **Date**: 2026-03-11
- **Context**: Blind test on 16 files: vocal-isolated clips scored 64% accuracy
  and 100% OOD rejection (2/2). Mix audio (full concert with instruments) scored
  38% accuracy and only 25% OOD rejection (2/8). The same system, same models,
  same thresholds -- the only difference was vocal isolation.
- **Rule**: Vocal isolation (Demucs or multitrack stems) must be a mandatory
  preprocessing step, not optional. Without it, pYIN picks up violin, tambura,
  and mridangam pitches that inflate scores and destroy margin-based rejection.
  Never evaluate or deploy without vocal isolation in the pipeline.
- **Impact**: Without this rule, the system appears to work in testing (vocal-only)
  but fails catastrophically on real-world concert recordings.

### L-029: Blind Testing Reveals What Self-Testing Hides
- **Date**: 2026-03-11
- **Context**: Sandbox testing (on seed features) showed 64% accuracy. The blind
  test on unseen mix audio from archive.zip showed 38%. The sandbox was right
  about vocal-isolated performance but couldn't predict mix-audio degradation.
  Additionally, the sandbox only tested 4 random files -- expanding to 16
  revealed the Thodi sink is far worse on OOD audio than expected (6/8 false pos).
- **Rule**: Always run a blind test with anonymized files BEFORE declaring a
  milestone. Include both known-raga and OOD-raga files. Include mix audio
  (not just vocal-isolated) to test real-world conditions. Sandbox results on
  training data are necessary but not sufficient.
- **Impact**: Prevents overconfidence. The 64% number is real for vocal-only,
  but the system is not ready for general audio without vocal isolation.

### L-030: IDF x Variance Is the Right PCD Weighting for Raga Discrimination
- **Date**: 2026-03-12
- **Context**: Tested 5 PCD scoring methods: baseline dot-product, mean-subtracted,
  cosine, IDF-only, variance-only, and IDF x variance combined.
  IDF x variance won decisively: 83% sandbox (vs 64% baseline), 70% production.
  It downweights common swaras (Sa, Pa) and upweights distinctive ones.
  This is the MIR equivalent of TF-IDF: common features are noise, rare features are signal.
- **Rule**: When a feature dimension is shared by all classes, it adds noise to
  similarity scoring. Weight each dimension inversely by its commonality (IDF)
  and variability (1/std). The combined weight focuses the dot-product on what
  actually distinguishes the classes.
- **Impact**: +6% production accuracy, Thodi sink halved, Kamboji and Kalyani
  dramatically improved. Single biggest architectural improvement after ALPHA fix.

### L-031: Sandbox Self-Evaluation Overestimates by 10-15%
- **Date**: 2026-03-12
- **Context**: Method E sandbox showed 83% accuracy on 53 clips. Production batch
  on the same 53 clips showed 70%. The 13% gap is because sandbox builds models
  and evaluates on the same clips (self-recognition bias). ChatGPT predicted
  ~75% for held-out data -- very close to actual 70%.
- **Rule**: Always expect 10-15% accuracy drop from sandbox to production when
  training and test sets overlap. Sandbox results are useful for comparing methods
  (relative ranking is preserved) but absolute numbers are optimistic.
  True accuracy requires held-out validation or cross-validation.
- **Impact**: Prevents overconfidence in sandbox results. The relative ordering
  of methods (E > D2 > C > A > baseline > B > D) is reliable even if absolute
  numbers are inflated.


### L-032: Hubness Correction Needs Scale to Work
- **Date**: 2026-03-12
- **Context**: Tested centered hubness correction (score = raw - avg_sim + global_mean)
  on 6 ragas / 53 clips with LOO validation. Thodi sink eliminated (0/8) but overall
  accuracy dropped 78.6% -> 74.2%. Multi-agent analysis found bias values (+-0.0003
  to +-0.0008) are below the noise floor of pYIN pitch extraction at 72 bins.
  With only 6 ragas (15 unique model pairs), avg_sim values are statistically fragile.
- **Rule**: Hubness correction requires sufficient model diversity to produce stable
  avg_sim values. At 6 ragas, the correction is too weak to help but strong enough
  to hurt. Wait for 15+ ragas (105+ unique pairs) before re-testing.
  Keep the sandbox script ready (sandbox_hubness.py).
- **Trigger**: Re-run sandbox_hubness.py when raga count >= 15.
- **Impact**: Prevents premature adoption of a correction that would reduce accuracy.
  The idea is correct; the timing is wrong.

### L-033: Leave-One-Out Is the Gold Standard for Small Datasets
- **Date**: 2026-03-12
- **Context**: Sandbox self-eval showed 83% (36-bin) and 90% (72-bin). Production
  batch showed 70%. LOO showed 66.7% (36-bin) and 78.6% (72-bin). The LOO numbers
  are the most trustworthy because they eliminate self-evaluation bias entirely.
  Each clip is scored against a model built WITHOUT that clip.
- **Rule**: For datasets under 100 clips, always use LOO cross-validation to get
  true accuracy. Self-eval overestimates by 10-15%. Production batch results fall
  between self-eval and LOO. LOO is pessimistic but honest.
- **Impact**: Prevents overconfidence. LOO confirmed that 72 bins genuinely improve
  accuracy (66.7% -> 78.6%), not just an artifact of self-evaluation.

### L-034: 72 Bins Resolve Microtonal Distinctions That 36 Bins Cannot
- **Date**: 2026-03-12
- **Context**: Shuddha Ma (~498 cents) and prati Ma (~590 cents) are 92 cents apart.
  At 36 bins (33 cents/bin), they land 2-3 bins apart. At 72 bins (17 cents/bin),
  they land 6 bins apart. This directly separates Kalyani (prati Ma) from
  Shankarabharanam (shuddha Ma). Same applies to komal vs shuddha Ri/Ga/Da.
  LOO results: Kalyani 58% -> 90%, wrongs halved from 14 to 6.
- **Rule**: PCD bin resolution must be fine enough to separate swaras that
  distinguish sibling ragas. For Carnatic music with 16 swarasthanas,
  72 bins (17 cents each) is the minimum for reliable microtonal separation.
  36 bins (33 cents) is too coarse. 96+ bins causes margin collapse (too sparse).
- **Impact**: Single largest accuracy gain in the project: +11.9% LOO accuracy
  from a pure code change with zero new data.

### L-035: Multi-Agent Analysis Is Decisive for Mixed-Result Decisions
- **Date**: 2026-03-12
- **Context**: Hubness correction showed mixed results (Thodi sink eliminated but
  accuracy dropped). The 5-expert multi-agent analysis provided unanimous clarity:
  park it, don't discard it. Each expert identified the same root cause from their
  domain (noise floor, statistical fragility, small-sample artifacts, maintenance
  burden). No single perspective would have been as convincing.
- **Rule**: When a fix shows mixed results (improves some metrics, hurts others),
  invoke the multi-agent analysis. The cross-domain perspectives cut through
  ambiguity. Reserve it for genuinely hard decisions (not routine fixes).
- **Impact**: Prevented both premature adoption (would have hurt accuracy) and
  premature rejection (would have lost a valuable future feature).


### L-036: Thin-Data Ragas Are Poison, Not Just Weak
- **Date**: 2026-03-20
- **Context**: Adding 3 new ragas (Abhogi=2, Saveri=3, Madhyamavati=2 clips)
  dropped LOO accuracy from 72.0% to 41.7%. They didn't just fail to recognize
  themselves -- they actively absorbed wrongs from established ragas.
  Saveri became a mega-sink (12/21 wrongs).
- **Rule**: Never include a raga in aggregation with fewer than 5 clips.
  Thin-data models are unstable and their IDF-amplified distinctive bins
  become false attractors. Use MIN_CLIPS_PER_RAGA guardrail.
  Keep the features staged; activate when data threshold is met.
- **Impact**: Without the guardrail, every new raga added with 1-3 clips
  would degrade the entire system.

### L-037: Duplicate Features Silently Inflate Accuracy
- **Date**: 2026-03-20
- **Context**: Feature extraction ran twice on some audio files, producing
  duplicate .npz files with different timestamps. This inflated clip counts
  (81 vs 68 actual) and biased mean models toward duplicated clips.
- **Rule**: Before aggregation, always audit for duplicates by matching
  raga + source filename prefix. The timestamp portion of .npz filenames
  varies between runs, so match on the content identifier only.
- **Impact**: Inflated confidence in model stability. Some ragas appeared
  to have more diverse training data than they actually did.

### L-038: Don't Kill Long-Running Processes at 80%
- **Date**: 2026-03-20
- **Context**: Killed a batch_evaluate.py run after 2 hours (80% complete)
  because it was using the wrong model. Should have let it finish since it
  only had ~20 min remaining, then discarded the results.
- **Rule**: If a long process is >50% complete, let it finish unless it's
  actively harmful (not just using wrong params). The cost of restarting
  from zero always exceeds the cost of waiting for completion.
- **Impact**: Wasted 2 hours of compute. Had to restart from scratch.

### L-039: Add Per-File Timeouts to Batch Processing
- **Date**: 2026-03-20
- **Context**: batch_evaluate.py had no per-file timeout. If pYIN hangs on
  a corrupted or very long audio file, the entire batch blocks indefinitely.
  Added ThreadPoolExecutor with PER_FILE_TIMEOUT=360s per file.
- **Rule**: Any batch processing script that runs external algorithms (pYIN,
  Demucs, etc.) on user-provided audio must have a per-file timeout.
  Use concurrent.futures.ThreadPoolExecutor with timeout, not signal-based
  approaches (which don't work on Windows threads).
- **Impact**: Prevents infinite hangs on bad files.


### L-040: Cross-Reference Raga Labels Against Authoritative Sources
- **Date**: 2026-03-21
- **Context**: 3/6 Kamboji clips were Harikambhoji. Parent vs janya confusion.
- **Rule**: Always verify raga labels against Saraga/Dunya metadata before training.
- **Impact**: Contamination hidden by apparent 66.7% accuracy.

### L-041: Honest Baselines Beat Inflated Numbers
- **Date**: 2026-03-21
- **Context**: Cleaning bad data dropped accuracy from 72% to 58.8%.
- **Rule**: Never keep bad data for better numbers. The honest number is the foundation.

### L-042: Per-Raga Dyad Weight Is a Trade, Not a Fix
- **Date**: 2026-03-21
- **Context**: Tested per-raga dyad weight overrides. Bhairavi=0.5/0.5 boosted
  Bhairavi from 50% to 90% but tanked Thodi from 83% to 43%. Bhairavi became
  a new sink (absorbing 5 wrongs). More aggressive overrides (0.4/0.6, 0.3/0.7)
  made it worse -- Thodi dropped to 0%. The override creates a scoring asymmetry:
  when Bhairavi gets dyad-heavy weight, its score becomes artificially high for
  clips that have any transition similarity, pulling in Thodi clips.
- **Rule**: Per-raga weight overrides trade accuracy between ragas rather than
  improving overall. They only work if the boosted raga's dyads are truly
  distinctive AND don't overlap with other ragas' dyads. For Bhairavi/Thodi
  (78% PCD overlap, shared komal swaras), this trade is always lossy.
  Better approach: add more diverse data to make PCD+dyads naturally distinctive.
- **Impact**: Prevents wasting time on weight hacks when the root cause is
  feature overlap. Bhairavi needs gamaka/phrase features, not weight tricks.

### L-043: Existing Datasets May Have Untapped Ragas
- **Date**: 2026-03-21
- **Context**: The Carnatic Varnam zip (already downloaded at D:\Swaragam\datasets)
  contained 28 recordings across 7 ragas. We had only used Kalyani (4) and
  Mohanam (4). The remaining 20 files included 5 Abhogi + 5 Saveri varnams --
  enough to activate both ragas past the MIN_CLIPS=5 guardrail.
- **Rule**: Before searching for new data sources, always check what you already
  have. Audit existing downloads, zips, and datasets for ragas you need.
  The cheapest data is data you already downloaded but forgot about.
- **Impact**: Activated 2 new ragas (Abhogi + Saveri) with zero download time.

### L-044: Janya Ragas Get Absorbed by Their Parent Melakarta
- **Date**: 2026-03-31
- **Context**: Abhogi (janya of Kalyani via Mela 65 Mechakalyani) activated
  with 7 clips but scored 0% LOO -- all 4 wrongs went to Kalyani. Abhogi
  uses a subset of Kalyani's swaras (S R2 G2 M2 D2 S), so its PCD is a
  subset of Kalyani's PCD. IDF weighting cannot separate them because
  Abhogi's distinctive bins are also present in Kalyani.
- **Rule**: When adding a janya raga whose parent melakarta is already modeled,
  expect PCD-based scoring to fail. Janya identification requires features
  that capture what's ABSENT (omitted swaras) or unique phrase patterns,
  not just what's present. Dyad weight override or phrase-level features
  may be needed.
- **Impact**: Adding more Abhogi clips alone won't fix this -- it's a
  structural limitation of PCD-only scoring for subset ragas.

### L-045: PCD-Heavy Weights (0.8/0.2) Give Fewest Wrongs at 7+ Ragas
- **Date**: 2026-03-31
- **Context**: Tested 4 weight configs on 7 ragas / 70 clips:
  0.6/0.4 -> 51.0% (24 wrongs), 0.7/0.3 -> 57.5% (17 wrongs),
  0.8/0.2 -> 64.9% (13 wrongs), 0.7/0.3 M=0.002 -> 66.7% (9 wrongs, 61% unknown).
  0.8/0.2 won: highest decided accuracy with fewest wrongs.
  At 7 ragas, dyads add more noise than signal because the 72x72 matrices
  are still sparse with 7-14 clips per raga.
- **Rule**: As ragas increase, PCD-heavy weights are safer because PCD
  is more stable with limited data. Increase dyad weight only when per-raga
  clip counts reach 15-20+ and dyad discrimination ratio exceeds 2.0x.
- **Impact**: +6.1% accuracy over 0.7/0.3. Locked as production default.

### L-046: Absent-Swara Penalty Fails When Gamakas Leak Across Swaras
- **Date**: 2026-04-01
- **Context**: Tested absent-swara penalty to separate Abhogi (S R2 G2 M2 D2)
  from Kalyani (S R2 G2 M2 P D2 N3). Two approaches tried:
  (1) Data-driven: detect "expected" bins from model PCD using median threshold.
      Result: 18 expected bins for Abhogi (should be ~5 swaras). Self-harm
      detected on 5/7 Abhogi clips. Every penalty level >= 0.10 made things worse.
  (2) Musicological: define swara bin ranges from theory, check presence/absence.
      Pre-flight revealed Abhogi clips have 6-19% energy at Pa (bins 27-31) and
      N3 (bins 69-71) from gamaka spillover (M2<->Pa slides, D2<->N3 approaches).
      The swaras are NOT actually absent — binary absent/present fails.
  Best result: penalty=0.05 gave +1 correct (Kalyani, not Abhogi) with 0 regressions.
  Abhogi stayed at 33% across all configurations.
- **Rule**: Absent-swara penalty requires swaras to be truly absent (near-zero PCD
  energy). In Carnatic music, gamakas (ornamental slides) spread energy from one
  swara into neighboring swaras' bin ranges. A raga that "lacks Pa" will still show
  5-15% Pa-region energy from gamaka leakage. The discrimination signal is
  QUANTITATIVE (energy ratio), not QUALITATIVE (present vs absent).
  Approaches that may work: relative energy ratio comparison, phrase-level
  transition patterns, or swara sequence detection.
- **Impact**: Prevents re-attempting binary absent-swara approaches. The Abhogi
  problem requires features that measure HOW MUCH of a swara, not WHETHER it exists.
  Adds to proven dead-end list alongside weight overrides (L-044).
- **Sandbox scripts**: sandbox_absent_swara.py (v1), sandbox_absent_swara_v2.py (v2),
  _diag_bin_positions.py (diagnostic)

### L-047: Production Script Corruption — Prepended Duplicate Block
- **Date**: 2026-06-24
- **Context**: `recognize_raga_v12.py` was corrupted in a prior session. A minified
  duplicate of the entire script (~120 lines) was prepended before the original code.
  Damage included: smashed imports (`import librosaimport os`), duplicate conflicting
  constants (`PER_RAGA_WEIGHTS = {}` vs `{Bhairavi: (0.5, 0.5)}`), duplicate function
  definitions (Python uses the FIRST definition, so the corrupted minified versions
  ran instead of the originals), JS-style `// ...` comments injected into Python,
  and silent error swallowing (no `traceback.print_exc()`) in the minified `recognize_raga()`.
- **Rule**: When a production script is corrupted, do NOT attempt to fix it by patching
  individual lines. Instead:
  1. Read the full file to identify the clean original vs the injected block
  2. Use `git diff` to confirm the extent of damage
  3. Strip the corrupted block with a targeted edit
  4. Verify with `py_compile` (syntax check) + module import (constants check)
  5. Confirm `git diff` is empty (byte-identical to last good commit)
  Never trust a "fixed" script without running all 4 verification steps.
- **Impact**: The corrupted script was silently using wrong logic — Bhairavi's (0.5, 0.5)
  override was disabled, and errors were being swallowed without logging.
  Would have produced subtly wrong results with no visible error signal.

### L-048: Python Uses the FIRST Definition of Duplicate Functions
- **Date**: 2026-06-24
- **Context**: When the script was corrupted with a prepended duplicate block, Python
  loaded the FIRST definition of each function (the corrupted minified ones). The
  original well-documented functions at the bottom were silently ignored.
- **Rule**: In Python, a module executes top to bottom, so the LAST definition
  wins: a later `def` (or `class`) rebinds the name, replacing the earlier
  function object, and a later top-level assignment replaces the earlier value.
  What made the corruption confusing is that the injected block was PREPENDED,
  so its definitions ran first and the original definitions further down
  replaced them — the surviving code was whichever copy appeared last in the
  file, not whichever was "correct." Either way, duplicate definitions in a
  production file are always a bug and must never be tolerated.
  Always check for duplicate `def` statements after any edit.
- **Impact**: Silent behaviour change with no error. Extremely hard to detect without
  reading the full file carefully.

### L-049: LOO Must Exclude the Held-Out Clip From EVERY Model Component, Not Just the Primary Feature
- **Date**: 2026-07-11
- **Context**: `sandbox_abhogi_ratio.py`'s `run_loo()` correctly recomputed
  `mean_pcd` excluding the held-out clip each fold, but pulled `mean_up`/
  `mean_down` straight from the full aggregated model (which still contained
  the held-out clip's own dyad contribution). This produced a leaked
  baseline of 68.3% (C=28/W=13/U=29) against the true canonical 64.1%
  (C=25/W=14/U=31) — a 4.2pp inflation on identical config and constants.
  Root cause: `load_features()` never loaded per-clip dyads in the first
  place, only PCD, so there was no data available to properly exclude them.
- **Rule**: A "leave-one-out" implementation is only as complete as its
  weakest excluded component. If a score combines multiple features (PCD +
  dyads here), EVERY feature's model average must be rebuilt from the
  held-out set, not just the one that's easiest to recompute. Before
  trusting any custom LOO script, verify per-fold exclusion against the
  checked-in canonical script (`sandbox_loo_v131_canonical.py`) on identical
  config — if the baselines don't match exactly, something in the fold
  logic is leaking, not the config.
- **Impact**: Every number `sandbox_abhogi_ratio.py` had ever reported was
  inflated until this was found and fixed. See BUG-015, L-050.

### L-050: A Positive Topline Delta Can Hide That the Target Metric Didn't Move
- **Date**: 2026-07-11
- **Context**: `sandbox_abhogi_ratio.py`'s auto-generated verdict logic only
  compares `best_acc` (overall decided accuracy) against baseline and prints
  "IMPROVEMENT" if positive. The corrected sweep showed +1.0% at
  ratio_weight=0.05 — but Abhogi (the raga BUG-015 exists to fix) scored
  IDENTICALLY at every single tested weight (C=1/W=2/U=4, 33%, flat). The
  entire +1.0% came from unrelated movement in Bhairavi and Thodi, plus
  a Mohanam regression (100%->50%) that the topline number doesn't surface
  at all.
- **Rule**: When testing a fix aimed at a specific failure mode (here:
  one raga), the target metric's own per-raga row is the only number that
  answers "did this work" — the topline delta answers a different question
  ("did anything shift"), and can be positive while the target is
  completely flat, or even while it regresses, if other ragas move more.
  Automated verdict logic ("IMPROVEMENT"/"REGRESSION") that only checks
  the topline should not be trusted for targeted fixes without manually
  checking the specific row.
- **Impact**: Following the script's own "ACTION: Apply ratio_weight=0.05"
  recommendation would have shipped a change that does nothing for Abhogi,
  silently degrades Mohanam, and gets credited as a win. See BUG-015.

### L-051: Prove Cache Faithfulness Before Substituting It for Live Computation
- **Date**: 2026-08-07
- **Context**: Q-001A needed pyin features across the corpus; live pyin was the
  dominant runtime bottleneck (~2 min/clip), while the production extractor
  already caches raw `f0` to `features_v12/*.npz`. Substituting the cache is
  only safe if it is provably identical, not merely assumed identical — a
  librosa version bump or a silent format change between cache-build time and
  experiment time would produce different numbers with no visible error.
  Q-001A therefore shipped a `--validate` mode
  (`sandbox_q001a_representation_sufficiency.py`) that, for every clip with a
  cache entry, recomputes pyin live and compares both the raw `f0` array and
  all five derived metrics (coverage, prec_raw, prec_corr, recall, residual).
- **Rule**: A cache may substitute for live computation only after an explicit
  validation run proves equivalence on the corpus in use — `f0` arrays equal
  AND every derived metric identical, not just array shapes or spot checks.
  Passing on `f0` alone is insufficient; the metrics are what the experiment
  actually consumes. Re-validate after any change to extraction or downstream
  pitch logic, or after a librosa upgrade.
- **Impact**: Q-001A/Q-001B run in seconds on cached clips instead of minutes
  per clip, with faithfulness demonstrated rather than assumed. Recorded as 30
  clips, 0 mismatches, maxdiff 0.00e+00 — this figure is documented in ADR-017
  and feature-registry.md, but the underlying validation run output is not
  committed to the repository. **Scope**: the validated set is those 30 clips.
  The cache directory contains more `.npz` files than were validated; their
  presence is not evidence of faithfulness, and any experiment relying on
  clips outside the validated subset should say so rather than inherit this
  result. Formalized as ADR-017.

### L-052: Mean-vs-Threshold Verdicts Are Fragile at Small n -- Use Separation Tests
- **Date**: 2026-08-07
- **Context**: Q-001A's original verdict logic compared the target raga's mean
  metric against a band derived from reference ragas (min-of-references
  precision floor, max-of-references residual ceiling). At n=7 for the target,
  a single outlier clip moves the mean across the threshold and flips the
  verdict — the test reports a binary pass/fail without reporting how strong
  or how reliable the underlying difference is. The final implementation
  replaced this with a two-sided permutation test on the difference of means
  (50,000 iterations) plus Cohen's d, computed on per-clip values pooled
  across references versus the target. The reference band is retained in the
  output but explicitly labelled "DESCRIPTIVE ONLY, not the verdict."
- **Rule**: A verdict on whether two groups differ must come from a separation
  test that reports both significance and effect size (permutation test +
  Cohen's d), never from a mean-versus-threshold comparison. State
  INCONCLUSIVE as a legitimate pre-registered outcome — at small n, "no
  significant separation" means the question is unresolved, not that the null
  is proven.
- **Impact**: Q-001A's result is reported as n=7, permutation p=0.39,
  Cohen's d=0.38, Abhogi median +0.35 vs references +0.39 — no evidence of
  degradation, with the uncertainty visible rather than hidden behind a
  threshold crossing. Carried forward as a standing requirement in
  Q-001B_Research_Plan.md's statistical design.

### L-053: FEATURE_VERSION Must Have One Owner, Not a Copy Per Script
- **Date**: 2026-08-07
- **Context**: `FEATURE_VERSION = "v1.2"` was independently hardcoded in four
  active scripts — `aggregate_all_v12.py`, `extract_new_clips.py`,
  `extract_new_thodi.py`, and `extract_pitch_batch_v12.py` — spanning both
  producers (which stamp the version into each `.npz`) and consumers (which
  check it on cache lookup). A format bump would require editing all four in
  the same commit; missing one leaves a producer and a consumer disagreeing,
  which fails as a silent cache miss or a stale-cache read rather than a
  visible error. This is the same class as BUG-016/BUG-017, where a duplicated
  constant drifted stale for a single commit and mislabelled a retired config
  as canonical.
- **Rule**: A constant shared across producer and consumer scripts has exactly
  one owner module that every other script imports. Here the owner is
  `scripts/feature_constants.py`. Never re-declare it, and never import it
  from a producer module — that pulls in import-time side effects.
- **Impact**: All four active hardcodings replaced with
  `from feature_constants import FEATURE_VERSION` (commit `f84e3f5`). Two
  further copies remain in `scripts/archive/` (`aggregate_dyads_v12_split.py`,
  `aggregate_pcds_v12_split.py`) — deprecated pre-v1.2 scripts, deliberately
  out of scope. A
  format bump is now a one-line change that every reader follows
  automatically. Formalized as ADR-017; extends the single-source discipline
  of ADR-015.

### L-054: A Matched Per-Clip Null Tests Sequence Structure Without Cross-Clip Independence -- But Cannot Reach Raga-Level Claims
- **Date**: 2026-08-17
- **Context**: Q-001B-A asked whether Abhogi stable-note sequences contain
  trigram structure beyond their own bigram statistics. Abhogi's 7 clips span
  only 2 independent compositional units (Evvari Bodhana 6, Nannu Brova Neeku
  1), which blocks any composition-held-out design. The gate was still runnable
  because each clip was tested against a null generated from *its own* bigram
  multigraph -- a doublet-preserving Eulerian-trail shuffle preserving that
  clip's bigram counts, length and endpoints exactly. No cross-clip resampling
  occurs anywhere, so each per-clip p-value is a valid finite-sample Monte-Carlo
  p-value under that clip's own conditional null, unaffected by what the other
  clips are or by how many compositions they share. The same run also computed
  an aggregate statistic across clips; that aggregate was reported as
  DESCRIPTIVE ONLY and entered no verdict cell, because its precision assumes 7
  independent units when the dataset supplies 2. Result: raw-significant 2/7,
  Holm-significant 1/7, verdict INCONCLUSIVE.
- **Rule**: When a gate's dataset is too composition-poor for held-out
  validation, a per-clip matched-surrogate test is still valid and is the
  cheaper gate to run first -- but scope its conclusion to what it measures.
  Per-clip significance establishes that *sequence* structure exists in those
  sequences; it does not establish raga-level generality, and it does not
  establish discrimination against any other raga. Any statistic that pools
  across clips requires an independence assumption the composition split may not
  support, so pool only as description, never as the verdict. INCONCLUSIVE
  records that the test could not distinguish the outcomes -- it does not
  establish absence of structure, and a non-significant clip is not evidence
  that the clip lacks structure.
- **Impact**: Q-001B-A closed as INCONCLUSIVE without inventing a magnitude
  floor or a consistency count to force a verdict. Q-001B remains ACTIVE and
  Q-001B-B remains BLOCKED on composition diversity rather than on method. All
  raw signal fell inside Evvari Bodhana; Nannu Brova Neeku (raw p = 0.29183)
  supplied none, so the 6/1 split limits generality. Sequence length varies
  173-492 symbols, so per-clip power is not uniform. The two raw-significant
  clips are length-ranks 1 and 4 of 7; ranks 2 and 3 are both non-significant,
  so these data show no monotone length-significance relationship. Non-uniform
  power cannot be ruled out as a contributor, but it is not demonstrated, and
  n=7 does not support separating length-related power from musical structure.
  Residual plug-in H2 bias was not independently quantified. Run logged in
  datasets.md (2026-08-17); artifacts at
  `Q001B-A results/run_20260817_074952_n50000_seed0/`.

### L-055: Parallel Reviewers Are Not Independent Evidence -- Challenge the Brief, Restrict the Tools
- **Date**: 2026-10-12
- **Context**: In the Q-003 Research Council, six separate subagents read a
  shared evidence brief. Four of them independently "found" the same
  same-singer tonic interval. All four had computed it from the same rows of
  one CSV, using the same base model. Separately, a mandatory section asking
  "what in the brief is wrong" caught three defects in the parent's own brief:
  an overstated peak pattern, a mislabelled clip, and a composition-identity
  claim drawn from filenames. Read-only behaviour rested on instructions
  alone, because every built-in agent type could run Bash.
- **Rule**: Separate contexts give *perspective diversity*, not *evidential
  independence*. Count a finding by its underlying source, not by how many
  reviewers reported it. N reviewers reading one dataset make one
  observation. Make every shared brief challengeable, by requiring each
  reviewer to report what in it is wrong or overstated. Enforce read-only with
  tool restrictions where possible, not with instructions alone. Label claims
  the parent did not verify as "reviewer-reported".
- **Impact**: Without this, a multi-agent review inflates confidence: one
  observation becomes "four confirmations". Errors in the brief propagate
  unchallenged into every reviewer's conclusions, and safety depends on each
  agent following its instructions. Applied in ADR-019 and the
  `/review-board` procedure.
