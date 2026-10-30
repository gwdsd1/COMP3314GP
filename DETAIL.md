# COMP3314 Group Project — CSA reproduction

> **Grayscale follow-up,2026-10-30:** At unchanged CSA11x2 -> ordinary LDA16/Tmax3/G2-P8, the best tested ten-split configuration is**81.84% +/- 1.96%** (fixed wider crop, identity, unit-column centered-cosine NN), versus shared77.47% +/- 5.41% and paper84.10%. HOSVD ties; matched PCA30->18 is83.50% +/- 2.29%, PCA22->16 is81.44% +/- 2.24%. This is an observed-probe-selected exploratory result, separate from the earlier84.13% shrinkage/rank extension and pool single maximum85.9375%. The Gabor88.75 representative remains unchanged. [Full new study](./docs/REPORT.md#orl-gray-recovery-20261030), [final data](./results/orl_gray_recovery_20261030/final_analysis.json). The current README/main charts use81.84%;77.47% remains historical. The20261030 figure edition is current and the20261027 edition is archived. Historical material below retains its batch labels.

> **Project classification:** full reproduction within the instructor-approved ORL, MNIST, and grayscale FERET scope. PIE omission, independent implementation, unknown settings, and numerical differences remain explicit.

> English translation of the former README, updated for publication on2026-10-27. Historical scores/protocols remain intact. Use the current [README](./README.md) and [TEAM_BRIEF](./docs/TEAM_BRIEF.md#reproduction-status) for publication scope and the new ORL follow-up. All three datasets/caches remain local.
>
> **Current report/README representative:** **88.75%±2.89%** (HOSVD start, context extension; ten splits, −2.15pp versus the paper90.90%). The full-square identity result **88.81%±2.97%** (full-square identity initialization variant; −2.09pp) is a separate variant. The dated experiment summaries below are historical batch records; they are not the current representative comparison.


Target paper: Xu et al., *Reconstruction and Recognition of Tensor-Based Objects With Concurrent Subspaces Analysis*, IEEE TCSVT 2008.

## Start here

| Documentation| Purpose|
|---|---|
| [Companion Report/Display Material](./docs/TEAM_BRIEF.md)| Organized by research questions: thesis and course requirements, implementation, TA scope, all experimental data and comparisons, critical analysis, folded appendices and original results index|
| [Complete handover document](./docs/HANDOFF.md)| New session reading first: project sources, papers, course screenshot requirements, teacher/TA emails, data and implementation, key results, verification boundaries and next steps|
| [Current reproduction report](./docs/REPORT.md)| Current results of three data sets, confirmation protocol, our group agreement, gap analysis, PIE description and submission points|
| [Overview of all experiments and data](./docs/REPORT.md#experiment-overview)| Executed experimental batches, data, paper gaps, expansion direction and result caliber, including negative results and historical protocol differences|
| [History Archive](./docs/HISTORY.md)| The contents of all 13 documents before sorting; topic selection, old plans, replies and previous experiments for traceability|
| [FERET data description](./FERET/README.md)| official matching, annotation, download integrity and reading convention|

## current status

- **2026-10-08 DATER fixed supervision extension has been completed and verified, negative results are retained.**A 2π cropped inner input, twenty identical splits, 24 dimensions: DATER direct NN is**71.64%±3.18%**, plus ordinary LDA 23 is **67.11%±3.59%**; CSA has the same conditions 74.33%/80.13%, PCA82.70%/88.81%. 20 new DATER models, reusing 40 controls, 120 ratings/38,400 predictions passed verification; 19/20 reached the upper limit of 20 rounds, and does not claim to have converged. DATER is a method extension. Unknown settings have not been confirmed by TA/author and do not replace CSA shared/optional parameters/expansion/probe extreme value. [Protocol, comparison, failure record and rerun](./docs/REPORT.md#orl-dater).
- **2026-10-08 All three controlled analyzes were completed and verified.**Error/cost zero fitting, σ × context four inputs × 20 scheduled split × four methods 320 models, probe eye point four-way perturbation 1280 score zero fitting. The fixed π context CSA24 + ordinary LDA 23 is**87.08%±2.30%**, which is +6.95pp compared to the 80.13% matching within the current round of 2π cropping (20/20 improvement), which is still 3.82pp behind the 90.9% of the paper; the PCA with the same budget is 91.08%. The context 2π/π of CSA390 is 91.16%/90.09%, and there is no common optimal input among the four methods. The low-dimensional CSAπ context four-way original image eye point ±1 pixel perturbation averages −0.08pp, and the range is limited to the public; the actual projection weight is 830/618792, and the native pre-computed feature projection + LDA + NN pairing is about 2.1–3.3 times faster, excluding Gabor/training. 320 models and 512,000 cleaning/disturbance prediction checks passed, and the old sharing/parameter selection/expansion/exploration extreme value is retained. The DATER plan was retained for this round; subsequent DATER has been completed separately, and the formal submission of materials still retains the plan. [Full results, evidence, limitations and follow-up planning](./docs/REPORT.md#orl-controlled).
- **2026-10-08 Limited optimization of the paper's dimensions within the crop has been completed and verified, but no substantial improvements have been made.**Four fixed inputs σ = 2π/π×zero/reflect, after gallery internal selection input/initialization/NN, CSA24+ordinary LDA 23 is**81.41%±2.41%**, which is only +0.16pp (2 wins,4 ties,and4 losses) relative to the paired baseline 81.25%, which is 9.49pp different from the 90.9% in the paper. The shared CSA390/PCA24→23/PCA33→25 is 88.41%/88.41%/91.69%, both decreased. 960 inner models, 40 new outer fittings + 40 historical comparisons, and independent verification passed. The number, size, model and sharing conditions of TA have been met, and the unknown settings are still our group's convention; the previous context expansion of 87.84%, the original sharing of 79.66% and the probe extreme value are retained respectively. [Before and after/paper comparison, frozen parameters and evidence boundaries](./docs/REPORT.md#orl-ta-crop).
- **ORL Finite iterations of the unknown parameters of the paper's dimensions have been completed and verified.**After three stages of selection in the gallery, CSA24+ordinary LDA 23 is **87.84%±3.28%**, which is 6.59pp higher than the fixed baseline of 81.25% and 3.53pp higher than the previous round of context 84.31%; it is still 3.06pp short of 90.9% in the paper, and 2/10 split reaches the paper number. The input stage contributes 87.81% to the main gain, and the subsequent power/initialization/NN has a net increase of about 0.03pp; eight groups choose the σ=π context, and the ten groups are all unit-norm columns/mean-centered cosine. The pure CSA390 of the shared solution is 91.03%, which is lower than 91.56% in the previous round. It cannot be said that the four methods are jointly optimal. 3520 inner models, 900 candidates, 120 new outer fittings, independent prediction/update verification passed; the context and power are our group expansion, unknown settings have not been confirmed by the author, and the original shared master table will not be replaced. [Parameters, all before and after comparisons and TA/the paper boundaries](./docs/REPORT.md#orl-unknown-parameters).
- **ORL Three sets of fixed input comparisons have been completed and verified.** Baseline/TT+equilibrium/context, the paper's dimensions, G2/P8, ten identical seeds, shared mean-centered cosine: CSA24+LDA23 is 81.25%/78.31%/**84.31%**, pure CSA390 is 90.00%/89.56%/**91.56%**. The context increased by 3.06/1.56pp respectively, with wins and losses of 9/0/1 and 8/1/1; PCA and other budgets 24→23 were 91.00%, and paper dimensions 33→25 were 94.38%. The new inputs are all our group extensions and do not replace the original shared master table or training-only validation selection; 120 models, 38,400 predictions and 60 independent CSA three rounds of verification passed, and the negative lighting results are retained. [Full comparison, diagnostics and protocol boundaries](./docs/REPORT.md#orl-next-directions).
- **MNIST four-step limited optimization has been completed and verified, CSA has not been improved.** The same 20–29 ten seeds, the original CSA of G30/G40 is 89.66%/90.50%, and the shared input/NN parameter selection in the gallery is 88.89%/90.18% (−0.77/−0.32pp); PCA is 86.67%/88.03%→86.94%/88.26%. The original 20–22 three-seed CSA also dropped from 90.34%/91.04% to 89.33%/90.34%. Retain the original main table and all negative results; meet the teacher's data volume, size, split, 5×8 Gabor, NN and Tmax=3 constraints, retain the Table IV dimension, unknown input/distance/initialization and statistical details still belong to our group agreement, and cannot be called the original authors' confirmation or accurate reproduction. [Comparison, TA/the paper range and rerun](./docs/REPORT.md#mnist-bounded-optimization).
- **200 best results exploration completed and verified.**G2/P8, Tmax=3, ordinary CSA32+LDA24 has the highest**95.00%**; pure CSA560 has the highest **97.50%**; retaining 390 dimensions has the highest **97.19%**. Their corresponding mean values ​​for the fixed configuration are 86.42%/91.43%/92.00% respectively. Press probe to select maximum. They cannot be regarded as stable mean or accurate original protocol reproduction. All 6,003 configurations, 1,200,600 ratings, and 6,432 near/exceeding paper indexes are retained. [Configuration, English description and rerun](./docs/REPORT.md#orl-best-search).
- **Previous training-only validation selection results are retained.**Ordinary Gabor CSA+LDA ten times mean**83.28%±3.30%**, the highest **89.06%**; shrinkage expansion mean **85.47%±4.57%**. Compared with the previous round of training optimization, the improvements were 0.81/0.72pp respectively; the ordinary process pure CSA390 mean **89.97%**. This group does not select parameters according to probe, and the new exploration maximum is reported separately. [Parameters, Controls and Analysis](./docs/REPORT.md#orl-csa-refinement).
- **Sample size expansion of fixed probe completed and verified.**The same P5, nested G2/G3/G5, 10 seeds: ordinary Gabor CSA+LDA**81.30%/88.10%/94.50%**, pure CSA390 **89.80%/93.95%/97.45%**. The same-dimensional PCA comparison and independent CSA update and recalculation were completed, with a total of 90 models verified and 64,400 prediction records; more training than the original G2/P8 reproduction was successful. [Full results and gap evidence](./docs/REPORT.md#orl-sample-size).
- **CSA+LDA subsequent optimization has been completed and verified.**After ten training-only validation selections, the ordinary LDA grayscale/Gabor is**78.56%±3.98% / 82.47%±3.14%**; the covariance shrinkage expands to **84.13%±2.38% / 84.75%±4.66%**. Compared with the previous paper, the dimension anchor point of the expansion increased by 6.66/5.09pp; with the same configuration, the shrinkage loss was 7.28/4.53pp. The regularized single-column extension does not claim that the original ordinary LDA has recovered the paper values. [Results and differences of this round](./docs/REPORT.md#csa-lda-optimization).
- **CSA+LDA special investigation has been completed.** Under the same NN origin, grayscale 22-dimensional CSA plus LDA increased from 71.84% to 77.47%, and Gabor24-dimensional increased from 77.00% to 79.66%; low rank means that adaptation to small sample LDA is the current weak link. Independent generalized eigendecomposition, NN, spatial axis and channel permutation found no implementation errors sufficient to explain the gap. For the two CSA targets, the reselection parameters during training decreased, and the negative results and the original main table were retained. For details, see [Special Analysis](./docs/REPORT.md#csa-lda).
- **2026-10-07 The original paper, TA protocol and code have been re-audited, and ORL eyesight/cropping and training-only validation selection have been corrected.** In this round, there were 240 outer model runs and 76,800 predictions. The first round, fixed parameter comparison and additional rank search all passed verification. See [Report Section 3](./docs/REPORT.md#orl) for details.
- has implemented and run **ORL, MNIST, original grayscale FERET**; PIE is omitted according to the teacher's permission, and the project is classified as full reproduction within that instructor-approved three-dataset scope.
- ORL new shared input + paper dimension, 10 seeds: pure Gabor CSA **90.19%±2.37%**, CSA+LDA **79.66%±2.77%**; 7.22/7.97 percentage points higher than the old freezing process. The parameters selected for the first round of training are **89.72% / 80.34%**; additional rank searches did not improve the mean and were kept intact. Still 94.4%/90.9% of the paper has not been accurately restored.
- MNIST shared process reuse and verification: PCA **87.52% / 88.58%**, CSA **90.34% / 91.04%**, corresponding to G30/P470, G40/P460. The old one-by-one method selects parameters to explore a single column.
- FERET shared fixed cosine control reuse and verification: CSA **88.73% / 94.25% / 95.38%**, corresponding to 50/100/200 training identities; old verification selected results in single column.
- The influence of the old eyespot has been confirmed by a fixed control with only changing coordinates; an independent CSA/LDA formula check found no core update errors. Previously, the gallery-only validation selection did not use the probe score of this round; the new 200 explorations used the probe score selection configuration and split. The historical probe has been observed, so the new blind test is not called.

## Directory Navigation

```text
COMP3314GP/
├─ README.md # Only entrance
├─ docs/
│ ├─ TEAM_BRIEF.md # Peer writing report/presentation: topic text, complete data folded appendix
│ ├─ REPORT.md # Current results and submission materials
│ ├─ HISTORY.md # the paper file unified file
│ └─ HANDOFF.md # Complete handover of new session
├─ csa.py / gabor.py # Core algorithm and original fixed Gabor
├─ audit_orl_protocol.py # Current ORL training optimization, fixed control and verification
├─ diagnose_csa_lda.py # Grayscale/Gabor CSA+LDA special positioning and verification
├─ optimize_csa_lda.py # ordinary LDA / shrinkage Extended in-training optimization and ablation
├─ refine_orl_csa.py # Gabor special parameters, HOSVD initialization, rank allocation and split sensitivity
├─ search_orl_best.py # 200 exploration searches, complete grid and best observation results replay
├─ optimize_mnist_protocol.py # MNIST shared input/NN, paper dimension, limited optimization in gallery and independent verification
├─ run_orl_fixed_inputs.py # ORL three sets of fixed inputs, 120 times the paper's dimensions / equal budget matching and independent verification
├─ optimize_orl_unknowns.py # Limited iteration within gallery of unknown input/amplitude/initialization/NN under the paper's dimensions
├─ optimize_orl_ta_crop.py # Crop within four inputs, the paper's dimensions shared parameter gallery limited optimization and verification
├─ dater.py / run_orl_dater.py # Fixed DATER supervision extension, 20 models, six-branch comparison
├─ verify_orl_dater.py / evaluate_orl_dater.py # Independent model verification and score reading correction entry
├─ run_orl_controlled.py # σ × context fixed 20 split, error/cost and probe disturbance, independent verification
├─ run_orl_sample_size.py # Fixed P5’s G2/G3/G5 expansion and same-dimensional PCA diagnosis
├─ run_shared_protocol.py / verify_shared_protocol.py # Compare the previous four steps
├─ *.py # Data processing, experiment and verification entrance
├─ data/ # ORL/MNIST data, eyes and features
├─ FERET/ # Authorized original data and official pairing
└─ results/ # Experiments, charts, protocols and source code snapshots
```

## Environment and Rerun

is executed from `COMP3314GP`. The dependency is locked in [requirements.txt](./requirements.txt), and the OpenCV preprocessing dependency is in [requirements-preprocess.txt](./requirements-preprocess.txt). Prepare your own Python environment for the first time:

```powershell
python -m pip install -r requirements.txt
python -m pip install --no-deps --target .deps -r requirements-preprocess.txt
```

The results are available and can be viewed directly. When re-running is required, use an output directory that does not yet exist; see [Report Operation Instructions](./docs/REPORT.md#outputs) for each entry and verification command.

## result entry

| content| save location|
|---|---|
| Latest ORL DATER method extension| [Six sets of results](./results/orl_dater/summary.csv);[Pairing changes](./results/orl_dater/paired_changes.csv);[Fixed protocol](./results/orl_dater/protocol.json);[ verification ](./results/orl_dater/verification.json);[Numerical sensitivity](./results/orl_dater/numerical_sensitivity.csv);[Result graph](./results/orl_dater/comparison.png);[Report and rerun](./docs/REPORT.md#orl-dater)|
| Latest ORL fixed controlled evidence| [Four input results](./results/orl_controlled/summary.csv);[Factors and interactions](./results/orl_controlled/factorial_effects.csv);[Error examples](./results/orl_controlled/historical_aligned_error_montage.png);[Measured cost](./results/orl_controlled/cost_benchmark.csv);[Disturbance summary](./results/orl_controlled/robustness_summary.csv);[Clean verification ](./results/orl_controlled/verification.json);[Disturbance verification](./results/orl_controlled/robustness_verification.json);[Comparison chart](./results/orl_controlled/comparison.png);[Report/Planning](./docs/REPORT.md#orl-controlled)|
| Latest ORL intra-clip optimization, negative results and compliance range| [before and after data](./results/orl_ta_crop_optimized/comparison.csv);[summary](./results/orl_ta_crop_optimized/summary.json);[group-by-group parameters](./results/orl_ta_crop_optimized/selected_settings.csv);[protocol](./results/orl_ta_crop_optimized/protocol.json);[verification ](./results/orl_ta_crop_optimized/verification.json);[Comparison chart](./results/orl_ta_crop_optimized/comparison.png);[Report](./docs/REPORT.md#orl-ta-crop)|
| ORL Finite iteration of unknown parameters| [Before and after and paper comparison](./results/orl_unknown_parameters/comparison.csv);[Parameter by group](./results/orl_unknown_parameters/selected_settings.csv);[Freeze protocol](./results/orl_unknown_parameters/protocol.json);[verification](./results/orl_unknown_parameters/verification.json);[Iteration diagram](./results/orl_unknown_parameters/iteration_comparison.png);[Report and scope](./docs/REPORT.md#orl-unknown-parameters)|
| MNIST limited optimization, negative results and compliance range| [Before and after ten times/paper comparison](./results/mnist_protocol_optimized/comparison.csv);[Original three pairings](./results/mnist_protocol_optimized/original_three_seed_comparison.csv);[Protocol](./results/mnist_protocol_optimized/protocol.json);[verification](./results/mnist_protocol_optimized/verification.json);[Comparison chart](./results/mnist_protocol_optimized/comparison.png)|
| 200 best observation results exploration| [maximum and parameters](./results/orl_best_search/best_results.json);[Close/exceed all runs of the paper](./results/orl_best_search/near_or_exceed.csv);[All configuration statistics](./results/orl_best_search/configuration_summary.csv);[Distribution graph](./results/orl_best_search/best_distribution.png)|
| The latest G2/P8 targeted iteration| [orl_csa_refined](./results/orl_csa_refined/);[Comparison chart](./results/orl_csa_refined/refinement_comparison.png);[All parameters](./results/orl_csa_refined/selected_settings.csv)|
| fixed configuration 100 times split diagnosis| [All scores](./results/orl_csa_refined/randomness/results.csv);[Distribution map](./results/orl_csa_refined/randomness_distribution.png);[verification](./results/orl_csa_refined/randomness/verification.json)|
| Fixed probe sample size expansion and verification| [orl_sample_size](./results/orl_sample_size/);[Learning Curve](./results/orl_sample_size/learning_curve.png);[Pairing Changes](./results/orl_sample_size/paired_changes.csv)|
| ordinary LDA / shrinkage extension optimization and verification| [csa_lda_optimized](./results/csa_lda_optimized/);[Result graph](./results/csa_lda_optimized/optimization_comparison.png);[All selected parameters](./results/csa_lda_optimized/selected_settings.csv)|
| CSA+LDA special diagnosis, selection of negative results and verification| [csa_lda_focus](./results/csa_lda_focus/);[Special comparison chart](./results/csa_lda_focus/diagnosis_comparison.png)|
| Current ORL audit/optimization, all predictions and verification| [orl_protocol_audit](./results/orl_protocol_audit/);[Complete CSV of the current three data sets](./results/orl_protocol_audit/shared_comparison.csv)|
| Comparison of the current ten ORL seeds and papers| [comparison.png](./results/orl_protocol_audit/comparison.png) |
| Eyespot/crop fixed control and image| [Cause comparison picture](./results/orl_protocol_audit/contrasts/comparison.png);[Crop comparison](./results/orl_protocol_audit/crop_comparison.png)|
| The results of the previous four steps and verification| [shared_protocol_final](./results/shared_protocol_final/) |
| Equal coefficients and seed-by-seed pairing differences| [paired_differences.png](./results/shared_protocol_final/step4/paired_differences.png) |
| Current ORL fixed branch| [orl_branches_v3](./results/orl_branches_v3/) |
| ORL Gabor single factor diagnosis| [orl_gabor_diagnosis](./results/orl_gabor_diagnosis/) |
| History MNIST and early ORL parameter selection exploration| [available_tuned](./results/available_tuned/) |
| Current FERET verification selected and fixed control| [feret_validation_selected_v3](./results/feret_validation_selected_v3/) |
| ORL Reconstruction, Convergence and Early Curves| [available_reproduction_v2](./results/available_reproduction_v2/) |

## Submit request

still needs to compile a 3-4 page LaTeX report, a 9-minute presentation and a 3-minute Q&A before submission, and publish a public code repository and running instructions. Code is assisted by Codex following thesis formulas, and the group is expected to review, understand, and disclose supporting sources. FERET raw data is subject to a license and is not released with public code; see [Submission Instructions](./docs/REPORT.md#submission) for complete ratings and reproduction bonus points.
