<p align="center">
  <img src="docs/logo.svg" alt="RealDataAgentBench logo" width="700" />
</p>

<p align="center">
  <strong>Most LLMs get the right answer. RDAB checks if they did it the right way.</strong>
</p>

<p align="center">
  <a href="https://github.com/patibandlavenkatamanideep/RealDataAgentBench/actions"><img src="https://github.com/patibandlavenkatamanideep/RealDataAgentBench/actions/workflows/ci.yml/badge.svg" alt="CI"></a>
  <a href="https://github.com/patibandlavenkatamanideep/RealDataAgentBench/actions/workflows/ci.yml"><img src="https://img.shields.io/badge/tests-196%20passing-brightgreen" alt="Tests"></a>
  <a href="https://www.python.org/"><img src="https://img.shields.io/badge/python-3.10%2B-blue" alt="Python"></a>
  <a href="https://github.com/patibandlavenkatamanideep/RealDataAgentBench/blob/main/LICENSE"><img src="https://img.shields.io/badge/license-MIT-blue" alt="License"></a>
  <a href="https://patibandlavenkatamanideep.github.io/RealDataAgentBench/"><img src="https://img.shields.io/badge/leaderboard-live-brightgreen" alt="Leaderboard"></a>
  <a href="SCORING_SPEC.md"><img src="https://img.shields.io/badge/scoring-fully%20transparent-blue" alt="Scoring spec"></a>
  <a href="tasks/"><img src="https://img.shields.io/badge/tasks-43%20(6%20real%20·%204%20messy)-orange" alt="Tasks"></a>
</p>

> **Frontier models score 0.84–0.99 on correctness.** Statistical validity ranges from 0.52 (feature engineering) to 0.90 (statistical inference). Models know when statistical language is expected — not when it's warranted. The gap is largest where it's least visible.

---

## TL;DR

- **12 models · 39 scored tasks (43 in the suite) · 4-dimensional scoring** — correctness alone misses where agents fail in production data workflows
- **gpt-4.1 leads at 0.875** — statistically tied with gpt-4.1-mini (0.870) at 65× higher cost per task; gpt-4.1-mini is the dominant cost-performance choice
- **A free model (Llama 3.3-70b, 0.798) scores higher than GPT-5 (0.780)** — Llama at 39/39 tasks with multi-run CI; GPT-5 covered only 23/39 tasks single-run (cost-prohibitive to scale), so treat this as directional, not a head-to-head match
- **Statistical validity is the differentiating dimension:** Claude leads on validity (Sonnet 0.851), GPT leads on correctness (gpt-4.1-mini 0.931) — the two correlate at r = 0.43, confirming they capture orthogonal capabilities
- **Prompting partly closes the stat-validity gap** — explicit uncertainty instructions raised GPT-4.1's mean stat_validity from 0.550 to 1.000 (+0.450), but qualitative review shows the gain is genuine on metric-reporting tasks and primarily lexical on feature importance tasks

---

## Leaderboard — 1,412+ runs · 12 models · 39 tasks

**→ [Open live leaderboard](https://patibandlavenkatamanideep.github.io/RealDataAgentBench/)** — filterable by category, sortable by score or cost

![Leaderboard screenshot](docs/screenshots/leaderboard.png)

| Rank | Model | RDAB Score | Runs | Cost / Task | Stat Validity | Coverage |
|:----:|-------|:----------:|:----:|:-----------:|:-------------:|:--------:|
| 1 | **gpt-4.1** | **0.875** | 119 | $0.033 | 0.747 | 39/39 ✓ |
| 2 | **gpt-4.1-mini** | **0.870** | 133 | $0.010 | 0.746 | 39/39 ✓ |
| — | claude-sonnet-4-6 ⚠️ | 0.857 | 29 | $0.317 | **0.851** | 23/39 |
| 3 | gpt-4o | 0.851 | 130 | $0.053 | 0.751 | 39/39 ✓ |
| — | claude-opus-4-6 ⚠️ | 0.846 | 23 | $1.628 | 0.793 | 23/39 |
| 4 | grok-3-mini | 0.827 | 228 | $0.004 | 0.704 | 39/39 ✓ |
| — | claude-haiku-4-5 ‡ | 0.809 | 230 | $0.175 | 0.788 | 39/39 ‡ |
| 5 | llama-3.3-70b | 0.798 | 71 | $0.002 | 0.694 | 39/39 ✓ |
| 6 | gpt-4o-mini | 0.785 | 123 | $0.012 | 0.777 | 39/39 ✓ |
| — | gpt-5 ⚠️ | 0.780 | 32 | $0.671 | 0.690 | 23/39 |
| 7 | gemini-2.5-flash | 0.662 | 206 | $0.002 | 0.538 | 39/39 ✓ |
| 8 | gpt-4.1-nano | 0.624 | 138 | $0.010 | 0.684 | 39/39 ✓ |

> ✓ = full 39-task multi-run CI &nbsp;·&nbsp; † = CI in progress &nbsp;·&nbsp; ⚠️ = single-run point estimate, no CI planned (cost-prohibitive) &nbsp;·&nbsp; ‡ = full task coverage, heterogeneous run counts (6 existing tasks single-run; the 10 added tasks at n=5 with 95% CI) — ranked position on the [live leaderboard](https://patibandlavenkatamanideep.github.io/RealDataAgentBench/)  
> **Ranking requires ≥80% task coverage** — see [SCORING_SPEC.md §10](SCORING_SPEC.md#10-ranking-eligibility--coverage-threshold)

> **Coverage caveats:** Models marked ⚠️ (Claude Sonnet, Claude Opus, GPT-5) cover 23/39 tasks — single-run, cost-prohibitive to scale. Their scores are point estimates with no CI and are not ranked. Cross-model comparisons involving ⚠️ models are directional signals, not controlled head-to-head results. Llama 3.3-70b vs GPT-5 (0.798 vs 0.780) is the most headline-able comparison — Llama at 39/39 full coverage with multi-run CI, but GPT-5's 23/39 single-run exposure means it ran a different (and likely easier) task mix, so the comparison is directional only. Findings that reference these models note this explicitly; all other findings involve ranked (✓) models only.

---

## Uncertainty Prompting Experiment — Headline Result

Can explicit uncertainty instructions close the correctness–validity gap? Two models, 5 tasks each, three prompt variants (V0 baseline / V1 uncertainty / V2 statistician). Correctness held at 1.000 across all runs — zero quality trade-off.

| Model | V0 baseline | V1 Δ | V2 Δ | Coverage |
|-------|:-----------:|:----:|:----:|:--------:|
| GPT-4.1 | 0.550 | **+0.450** | +0.400 | 5/5 tasks |
| Llama 3.3-70B | 0.500 | **0.000** | 0.000 | 3/5 tasks |

GPT-4.1 responded with genuine SE computations and bootstrap attempts. Llama's output was word-for-word equivalent to baseline — no uncertainty language of any kind. **The prompting lever works only for models that follow complex system-prompt instructions.** Full results → [docs/experiments/results_summary.md](docs/experiments/results_summary.md)

---

## Key Findings

> **Insight 1 — Statistical validity is category-dependent, not uniformly weak**
>
> By category: stat inference = 0.897 · EDA = 0.849 · ML engineering = 0.740 · modeling = 0.603 · feature engineering = 0.520. Models reach for statistical language reactively when cued by the task name — not proactively when warranted. Feature engineering is worst: models report importances and coefficients without uncertainty bounds because nothing in the task name signals that statistics are expected.
>
> By model family: Claude leads on stat-validity (Sonnet 0.851, Opus 0.793, Haiku 0.790); GPT leads on correctness (gpt-4.1-mini 0.931). Correctness × stat-validity correlate at r = 0.43 — largely orthogonal capabilities. **Aggregate rank masks two independent gradients.**

---

> **Insight 2 — No single model dominates across categories**
>
> | Category | Best Model | Avg RDAB |
> |----------|-----------|:--------:|
> | EDA | gpt-4.1-mini | 0.939 |
> | Feature Engineering | gpt-4.1 | 0.846 |
> | Statistical Inference | gpt-4.1 | 0.957 |
> | ML Engineering | gpt-4.1-mini | 0.866 |
> | Modeling | claude-sonnet-4-6 ⚠️ | 0.871 |
>
> Llama 3.3-70b (free, 39/39 tasks) scores higher than GPT-5 (0.798 vs 0.780) — see coverage caveats above. **Benchmark on your actual task mix before committing to a provider.**

---

> **Insight 3 — Claude models massively over-spend tokens**
>
> Claude Haiku: 608,861 tokens on `feat_005` (efficiency = 0.13). Claude Sonnet: 375,920 tokens on `feat_004`. GPT-4.1 and Llama completed the same tasks in under 30,000 tokens with higher correctness. The Anthropic models explore more — but conclude less efficiently. **Token count is a capability signal, not just a cost one.**

---

> **Insight 4 — Multi-run CI reveals gaps that single-run zeros conceal**
>
> Grok-3-mini at n=1 on 23 tasks showed correctness = 0.00 on 7 sklearn-dependent tasks. At n=5 on 39 tasks, that collapses to correctness averaging 0.50–0.89 on modeling — the bimodal shape persists, but the model retries, occasionally adapts, and occasionally gives up. **The blind spot is real but probabilistic, not deterministic.**

---

> **Insight 5 — The best model is rarely the most expensive**
>
> gpt-4.1-mini (0.870) is statistically tied with gpt-4.1 (0.875) at 65× lower cost ($0.010 vs $0.033 per task). At production scale, that cost gap determines whether agentic data workflows are economically viable. GPT-5 comparison is directional only — see coverage caveats above.

---

> **Insight 6 — Prompting closes the stat-validity gap for GPT-4.1; has zero effect on Llama**
>
> See → [Uncertainty Prompting Experiment — Headline Result](#uncertainty-prompting-experiment--headline-result) below.

---

## Observed Failure Patterns

**Pattern 1 — Correct number, wrong reasoning** (`feat_002`, `feat_003`, `model_001–003`):  
Every model computes the right feature importances or coefficients — then stops. No model spontaneously reports whether the ranking is stable across folds or whether the model is overfit. Correctness = 1.0, Stat Validity = 0.25.

**Pattern 2 — Token spiral without convergence** (Claude models, `feat_004`, `feat_005`, `model_003`):  
Claude Opus and Haiku loop over `get_column_stats` on every column one-by-one, re-running the same `run_code` block with minor variations. Correct intermediate outputs, 5–15× the token budget. Efficiency scores as low as 0.12.

**Pattern 3 — Namespace blind spot** (grok-3-mini, all modeling tasks):  
Grok-3-mini attempts to import sklearn inside `run_code`, hits the namespace restriction, retries repeatedly, and occasionally gives up entirely. The model never adapts to the pre-injected namespace. 7 zero-correctness runs on tasks it could theoretically solve.

**Pattern 4 — Gemini over-truncates** (`mod_003`, `model_002`, `feat_005`):  
Gemini 2.5 Flash produces structurally correct code but truncates its final answer before reporting key metrics. Avg correctness = 0.58 despite reasonable reasoning — it reaches the right place but doesn't output a scoreable conclusion.

---

## Why RDAB is Different

Most benchmarks ask: *"Did the agent get the right answer?"* That is not enough.

| Dimension | What it catches |
|-----------|----------------|
| **Correctness** | Right skewness direction, correlation sign, missing column counts |
| **Code Quality** | Vectorized ops, descriptive names, no raw loops |
| **Efficiency** | Token and step budget vs. task complexity |
| **Stat Validity** | Uncertainty reporting, appropriate tests, no causal overreach |

**An agent can score 1.0 on correctness and 0.25 on statistical validity on the same task.** That delta is what RDAB measures — and what every other benchmark ignores.

| Feature | **RDAB** | [AgentBench](https://github.com/THUDM/AgentBench) | [DA-Code](https://github.com/xlang-ai/DA-Code) | [ScienceAgentBench](https://github.com/OSU-NLP-Group/ScienceAgentBench) | [HELM](https://github.com/stanford-crfm/helm) |
|---------|:--------:|:----------:|:-------:|:-----------------:|:----:|
| Statistical validity dimension | ✓ | ✗ | ✗ | Partial | ✗ |
| 95% CI on leaderboard | ✓ | ✗ | ✗ | ✗ | ✗ |
| Per-run cost tracking | ✓ | ✗ | ✗ | ✗ | ✗ |
| Seeded reproducible datasets | ✓ | ✓ | ✗ | ✗ | ✓ |
| Fully local (no external download) | ✓ | ✗ | ✗ | ✗ | ✗ |
| LLM-as-judge calibration | ✓ | ✗ | ✗ | ✗ | ✗ |
| Category-aware scoring | ✓ | ✗ | ✗ | Partial | Partial |
| Real-data tasks | ✓ | ✗ | ✓ | ✓ | ✗ |
| Open source harness | ✓ | ✓ | ✓ | ✗ | ✓ |

---

## Quickstart

```bash
git clone https://github.com/patibandlavenkatamanideep/RealDataAgentBench
cd RealDataAgentBench && pip install -e ".[dev]"

cp .env.example .env              # add your API key(s)

dab run eda_001 --dry-run         # validate environment (no API call)
dab run eda_001 --model gpt-4.1   # single live run

# 3 runs per task gives 95% CI estimates (~3× cost, strongly recommended)
dab run --all --model gpt-4.1 --runs 3 --temperature 0
```

```bash
dab list                          # browse all 43 tasks
dab score outputs/<file>.json     # re-score any saved trace
dab models                        # check supported models + API key status
```

Free option — no credit card required:

```bash
# Add GROQ_API_KEY to .env (console.groq.com)
dab run --all --model groq --runs 5  # llama-3.3-70b-versatile, ~$0.007 total
```

---

## Scoring

Each task is scored across four independent dimensions, then combined into a weighted **RDAB Score**:

| Dimension | What it measures | Typical weight |
|-----------|-----------------|:--------------:|
| **Correctness** | Ground truth match — skewness, correlation sign, column counts | 40–50% |
| **Code Quality** | Vectorized ops, descriptive names, no raw loops | 15–20% |
| **Efficiency** | Tokens and steps vs. per-task budget | 15% |
| **Stat Validity** | Uncertainty reporting, appropriate methods, no causal overreach | 15–30% |

Weights are defined per-task in the YAML. The full specification — every formula, regex, threshold, and known limitation — is in **[SCORING_SPEC.md](SCORING_SPEC.md)**. Every leaderboard score is independently reproducible from that document alone without reading source code.

---

## Scorer validity

The Stat-Validity scorer is **lexical** — it detects statistical *language* via regex, not statistical *validity*. The central finding ("models use statistical language when cued, not when warranted") is therefore measured by a statistical-language detector, which is a circularity worth confronting directly rather than hiding. So I calibrated the lexical scorer against an **LLM judge** (Claude Haiku 4.5 applying a structured rubric) on a stratified sample of 120 answers (24 per category), and I'm reporting the result as-is — including where it's unflattering.

**Reproduce it:** `python scripts/calibrate_stat_validity.py --n 120 --seed 42 --out docs/scorer_calibration.json` (the committed [docs/scorer_calibration.json](docs/scorer_calibration.json) is that run; judge cost was $0.17).

| Category | n | Lexical mean | Judge mean | Pearson r | Cohen's κ† |
|----------|:--:|:----:|:----:|:----:|:----:|
| EDA | 24 | 0.83 | 0.69 | 0.60 | 0.39 |
| Feature Engineering | 24 | 0.56 | 0.52 | 0.23 | 0.18 |
| ML Engineering | 24 | 0.77 | 0.72 | 0.39 | 0.35 |
| Modeling | 24 | 0.60 | 0.58 | 0.23 | 0.42 |
| Statistical Inference | 24 | 0.95 | 0.88 | 0.15 | 0.18 |
| **Overall** | **120** | **0.74** | **0.68** | **0.48** | — |

† κ is pooled over the four binary criteria within each category. The `avoids_p_hacking` criterion is degenerate (the lexical check fires positive on 100% of answers), which has no variance and deflates the pooled κ.

**What this says, honestly:**

- **Per-answer agreement is weak.** No category reaches the κ ≥ 0.7 "substantial agreement" bar; overall lexical-vs-judge correlation is r = 0.48. By the calibration script's own interpretation guide, this is the "consider replacing with the judge" band. **Do not over-interpret an individual answer's stat_validity score** — treat it as a noisy proxy.
- **The disagreement is directional and matches the [gaming examples](SCORING_SPEC.md#4-statistical-validity--range-025--050--075--100).** The lexical scorer **over-credits uncertainty** (flags it on 58% of answers vs. the judge's 33% — keyword salad like "robust and stable, approximately 0.85" scores credit it shouldn't) and **under-credits interpretation** (flags it on 52% vs. the judge's 67% — rigorous answers phrased outside the regex vocabulary are missed). These are exactly the two failure modes the worked examples in SCORING_SPEC §4 demonstrate.
- **But the category-level conclusions hold up.** The lexical and judge **means track closely** (overall bias is only −0.065, lexical scoring slightly high), and the judge preserves the headline ordering — Feature Engineering is the weakest category and Statistical Inference the strongest under *both* scorers. So [Insight 1](#key-findings) (stat-validity is category-dependent, weakest on feature engineering) survives the judge; what doesn't survive is trusting any *single* answer's lexical score.
- **Recommendation:** use the lexical scorer as a cheap aggregate signal and pre-filter; for rigorous per-answer work, run the LLM judge as the primary scorer. This is tracked as limitation **L4** in [SCORING_SPEC.md §8](SCORING_SPEC.md#8-honest-limitations--what-we-know-and-plan-to-fix).

---

## Tasks

**43 tasks** across 5 categories: EDA (8), Feature Engineering (9), Modeling (8), Statistical Inference (9), ML Engineering (9). Difficulty spans easy (skewness, log transform) to hard (nested cross-validation, multicollinearity, Simpson's paradox). Three data provenance classes (see [Data provenance & contamination](#data-provenance--contamination)):

- **33 clean synthetic** — seeded generators, ground-truth control, not memorisable.
- **6 real** — publicly licensed UCI/sklearn datasets with independently computed ground truths.
- **4 messy synthetic** — seeded generators that inject real-world dirt (duplicate rows, text-encoded numerics, inconsistent categorical labels, MNAR missingness, target leakage); the cleaning *is* the task. Newly added — **the leaderboard's 1,412 runs predate these 4, so they are not yet scored.**

<details>
<summary>All 43 tasks with descriptions</summary>

The 6 real-data tasks (`eda_004`, `eda_005`, `feat_006`, `model_006`, `stat_006`, `mod_006`) use publicly licensed datasets from UCI and sklearn. Ground truths are computed independently from the actual data — reproducible by running `sklearn.datasets.load_*()` directly.

### Exploratory Data Analysis (8 — 5 synthetic · 2 real · 1 messy)

| ID | Title | Difficulty | Key Concepts |
|----|-------|:----------:|-------------|
| eda_001 | Income Distribution Analysis | Easy | Skewness, log transform |
| eda_002 | Patient Records — Missing Data & Outlier Audit | Medium | Missing rates, IQR outliers |
| eda_003 | E-Commerce Confounding Variable Detection | Hard | Simpson's Paradox, partial correlation |
| eda_004 ⭐ | **[Real]** Breast Cancer Wisconsin — Feature Distribution & Malignancy Predictors | Medium | Real UCI data, correlation, class imbalance |
| eda_005 ⭐ | **[Real]** Iris Dataset — Species Separability & Feature Importance | Easy | Real Fisher (1936) data, linear separability |
| eda_006 | Salary Survey — Compensation Distribution & Benchmark Analysis | Easy | Skewness, log transform, department comparison |
| eda_007 | Manufacturing Quality — Process Variation & Defect Analysis | Medium | Std dev by machine, defect rate, correlation |
| eda_011 🧹 | **[Messy]** Data-Quality Audit of a Dirty Orders Export | Medium | Duplicate rows, text-encoded currency, inconsistent labels |

### Feature Engineering (9 — 7 synthetic · 1 real · 1 messy)

| ID | Title | Difficulty | Key Concepts |
|----|-------|:----------:|-------------|
| feat_001 | Polynomial Feature Engineering for House Prices | Easy | Interaction terms, R² comparison |
| feat_002 | Categorical Encoding & Feature Selection | Medium | One-hot encoding, RF feature importance |
| feat_003 | Datetime Feature Extraction for Retail Sales | Medium | Datetime parsing, weekend effect |
| feat_004 | Feature Selection Pipeline for Credit Risk | Hard | Multicollinearity, ROC-AUC, Gradient Boosting |
| feat_005 | Feature Engineering for Imbalanced Fraud Detection | Hard | SMOTE, F1-score, class imbalance |
| feat_006 ⭐ | **[Real]** Diabetes Dataset — Feature Correlation & Regression Baseline | Medium | Real Efron et al. (2004) data, feature ranking, R² |
| feat_009 | Employee Attrition — Categorical Encoding & Feature Importance | Medium | Label vs one-hot, ordinal encoding, RF importance |
| feat_010 | Retail Sales — Lag & Rolling Window Features for Time Series | Hard | Lag features, rolling mean, autocorrelation |
| feat_011 🧹 | **[Messy]** Cleaning Dirty Sensor Readings with Non-Random Missingness | Medium | MNAR missingness, IQR outliers, duplicate packets |

### Modeling (8 — 7 synthetic · 1 real)

| ID | Title | Difficulty | Key Concepts |
|----|-------|:----------:|-------------|
| model_001 | Logistic Regression for Diabetes Prediction | Easy | Coefficients, ROC-AUC, feature ranking |
| model_002 | Random Forest for Wine Quality | Medium | Feature importance, CV tuning, F1 |
| model_003 | Ridge vs Lasso for Student Performance | Medium | Regularization, RMSE, sparsity |
| model_004 | Gradient Boosting for Customer Churn | Hard | Confusion matrix, CV AUC, model comparison |
| model_005 | Multi-Model Regression for Energy Consumption | Hard | RMSE comparison, CV R², feature importance |
| model_006 ⭐ | **[Real]** Wine Recognition — Multi-Class Classification with Feature Analysis | Medium | Real UCI data, RF vs LR, flavanoids |
| model_009 | Wine Quality — Linear Regression vs Random Forest Comparison | Medium | RMSE, R², model comparison, numeric target |
| model_010 | House Prices — Ridge vs Lasso Regularization Comparison | Medium | Regularization, sparsity, coefficient shrinkage |

### Statistical Inference (9 — 7 synthetic · 1 real · 1 messy)

| ID | Title | Difficulty | Key Concepts |
|----|-------|:----------:|-------------|
| stat_001 | A/B Test — Conversion Rate Experiment | Easy | z-test, confidence intervals, lift |
| stat_002 | Clinical Trial — Drug Efficacy Test | Medium | t-test, Cohen's d, baseline balance |
| stat_003 | Salary Gap Analysis — Controlling for Confounders | Hard | OLS regression, pay gap, confounding |
| stat_004 | Time Series Decomposition — Sales Trend & Seasonality | Medium | Decomposition, trend, seasonality |
| stat_005 | Statistical Process Control — Manufacturing Defects | Hard | Cp index, drift detection, chi-squared |
| stat_006 ⭐ | **[Real]** Iris Species — One-Way ANOVA for Petal Length Separation | Medium | Real Fisher (1936) data, ANOVA, F-statistic |
| stat_009 | Salary Survey — Mann-Whitney Test for Non-Parametric Gender Comparison | Medium | Mann-Whitney U, non-parametric, null result |
| stat_010 | Employee Attrition — Chi-Squared Test for Overtime & Attrition Independence | Easy | Chi-squared, contingency table, Cramér's V |
| stat_011 🧹 | **[Messy]** Two-Group Test on a Survey with Dirty Labels & Duplicate Respondents | Medium | Label canonicalization, dedup, Welch t-test |

### ML Engineering (9 — 7 synthetic · 1 real · 1 messy)

| ID | Title | Difficulty | Key Concepts |
|----|-------|:----------:|-------------|
| mod_001 | Data Leakage Detection in Model Selection | Easy | Target leakage, correlation, AUC drop |
| mod_002 | K-Fold Cross-Validation vs Single Hold-Out | Easy | CV variance, small dataset evaluation |
| mod_003 | Probability Calibration for Heart Disease Prediction | Medium | Brier score, Platt scaling, reliability |
| mod_004 | Ensemble Voting vs Individual Models | Medium | VotingClassifier, soft voting, F1 |
| mod_005 | Nested Cross-Validation for Unbiased Tuning | Hard | Selection bias, GridSearchCV, nested CV |
| mod_006 ⭐ | **[Real]** Breast Cancer Wisconsin — K-Fold CV vs Hold-Out on Real Clinical Data | Medium | Real UCI data, CV variance, stratification |
| mod_009 | Fraud Detection — Decision Threshold Optimization for Recall-Weighted F-Score | Medium | Threshold sweep, precision-recall, F-beta |
| mod_010 | Credit Risk — Feature Importance Stability via Bootstrap Resampling | Hard | Bootstrap, stability, confidence intervals |
| mod_011 🧹 | **[Messy]** Data-Quality & Leakage Gate Before Modeling Loan Defaults | Hard | Target leakage (AUC=1.0), dedup-before-split, dirty labels |

</details>

---

## Data provenance & contamination

Every serious benchmark now has to answer "could the model have seen this before?" Here's the honest accounting, by provenance class:

| Class | Count | Memorisation risk | Real-world messiness | Why it's here |
|-------|:--:|-------|-------|---------------|
| **Clean synthetic** | 33 | **Low** — seeded `numpy` generators; the exact numbers can't be in training data | Low — cleaner than reality | Ground-truth control: the correct answer is computable exactly from the seed |
| **Real (UCI/sklearn)** | 6 | **High** — Iris, Wine, Breast Cancer, Diabetes are the most-memorised datasets in ML; frontier models can often recite their structure | Low — these are textbook-clean | Distribution realism + independently computable ground truth — but see the caveat below |
| **Messy synthetic** | 4 | **Low** — seeded, novel | **High** — duplicates, text-encoded numerics, inconsistent labels, MNAR nulls, target leakage | The cleaning *is* the task; rewards models that audit data instead of trusting it |

**The honest caveat on the "real" tasks.** The six real datasets are `real_iris`, `real_wine`, `real_breast_cancer`, and `real_diabetes` — four of the most famous toy datasets in machine learning, all 150–700 rows, all plausibly memorised from training. They are the **worst of both worlds**: in-distribution for memorisation *and* far cleaner than operational data. They are kept for independently reproducible ground truth (run `sklearn.datasets.load_*()` yourself), not because they're hard. **A model reciting Iris petal-length statistics from memory is not evidence of data-analysis skill.** This is a known weakness of the original task set, stated plainly rather than hidden.

**What the messy-synthetic tasks fix.** They address both failure modes the toy datasets share: they are seeded (so not memorisable) *and* dirty (so they penalise the over-clean assumption). A model that runs `df.mean()` on the raw frame gets the wrong answer — it must detect duplicates, parse text-encoded numbers, canonicalise inconsistent labels, recognise non-random missingness, and catch target leakage first. In our scoring sanity check, a correctly-cleaned answer scores 1.00 and a naive raw-frame answer scores 0.00 on every messy task.

**What's still missing (roadmap).** These four are *synthetic* messiness — realistic dirt, but not literally a scraped real-world dataset. Genuinely external, license-cleared, harder-to-memorise data (e.g. a vendored UCI Adult/Census snapshot, NYC TLC, CDC BRFSS) is the next step; it was deferred here because the build environment blocks runtime dataset fetches and bundling external data has licensing/size/reproducibility tradeoffs that deserve their own PR.

---

## Uncertainty Prompting Experiment (Pre-registered)

Key result at [top](#uncertainty-prompting-experiment--headline-result). Per-model detail: [Two-model summary](docs/experiments/results_summary.md) · [GPT-4.1](docs/experiments/results_gpt41.md) · [Llama](docs/experiments/results_llama.md)

---

## Why RDAB is Credible

- **Every score is independently reproducible.** [SCORING_SPEC.md](SCORING_SPEC.md) documents every formula, regex, threshold, and known limitation — no source code reading required.
- **Known limitations are disclosed — for all four scorers, not just one.** The stat-validity scorer is lexical; `scripts/calibrate_stat_validity.py` quantifies its gap vs. an LLM judge (Pearson r, Cohen's κ — see [Scorer validity](#scorer-validity)). The Correctness and Code-Quality scorers are audited to the same bar in [SCORING_SPEC.md §1–§2](SCORING_SPEC.md#1-correctness--range-0010), each with a worked example showing how it can be gamed or produce a false negative (e.g. a number-spray scoring 1.0; crashing code scoring 1.0). The one outright bug that audit surfaced — a correct `$90,383.21` scoring 0 — was fixed (v1.8) and verified to change 0 of 1,356 existing traces. Nothing is presented as more rigorous than it is.
- **Partial-coverage models are excluded from ranking.** Any model below 80% task coverage is flagged and unranked. Their scores are not averaged against different task sets.
- **Data provenance is disclosed, including its weaknesses.** Six tasks use publicly licensed real datasets (UCI Breast Cancer, Iris, Diabetes, Wine) — but those are famous, memorisable toy sets, stated plainly in [Data provenance & contamination](#data-provenance--contamination). Four newer messy-synthetic tasks add seeded, non-memorisable real-world dirt (duplicates, text-encoded numerics, MNAR nulls, target leakage) where the cleaning is the task.
- **The key experiment is pre-registered.** Outcome interpretations committed before any runs were executed. Results reported against those pre-committed criteria without post-hoc adjustment.
- **CI leaderboard re-scores, does not rebuild from scratch.** Raw `outputs/` traces are not committed to the repo (size). The GitHub Actions leaderboard workflow re-scores the existing `docs/results.json` when scoring logic changes — it cannot regenerate run data. To extend the leaderboard, run `dab run --all --model <model> --runs 3` locally and update `docs/results.json`.

---

## Benchmark Methodology

**`dab run <task> --dry-run`** — Validates dataset loading and YAML parsing. No API call. Use this to verify your environment.

**`dab run <task>`** — Live mode. The agent receives a restricted Python namespace (not a security sandbox — see [SECURITY.md](SECURITY.md)) with the seeded dataset pre-loaded and iterates until it produces a final answer or hits the step/timeout limit. Every tool call, token count, and final answer is recorded in the trace JSON. No simulation, no pre-cached responses — every leaderboard score is from a live API call.

**Datasets:** Seeded synthetic generators (33 tasks) and publicly licensed UCI/sklearn datasets (6 tasks). All generated locally at runtime. Trace outputs write to your local `outputs/` directory.

**Scoring:** The four scorers (`correctness`, `code_quality`, `efficiency`, `stat_validity`) run independently on the trace JSON. The composite RDAB Score is a weighted average using per-task weights from the task YAML.

---

## Known Limitations

**Partially-lexical stat-validity scorer.** Check 1 (uncertainty quantification) was patched in v1.5 to require a decimal number within 200 characters of a keyword match — lexical-only matches now score 0.5× instead of 1.0×. Score impact: −0.001 to −0.034 per model across 1,356 traces. Residual limitation: the numeric-evidence window is loose (any decimal qualifies, not specifically a CI bound or SE). Check 3 (interpretation) remains fully lexical. See [SCORING_SPEC.md §4](SCORING_SPEC.md#4-statistical-validity--range-00-10) for the full spec.

**Synthetic-heavy task set.** 33 of 43 tasks use clean seeded generators. Four newer **messy-synthetic** tasks now specifically test robustness to real-world data-quality issues — mixed/text-encoded dtypes, duplicate records, inconsistent categorical encoding, non-random (MNAR) missingness, and target leakage; the cleaning is the task. The 6 "real" datasets are famous, memorisable toy sets — see [Data provenance & contamination](#data-provenance--contamination). Genuinely external, license-cleared real data (e.g. a vendored UCI Adult/Census snapshot) remains future work.

**String-match correctness.** Ground-truth matching checks for key values or phrases in the final answer. Verbose outputs may satisfy the check when terse correct outputs do not — most relevant to EDA tasks.

**Coverage policy.** Models below 80% task coverage are excluded from ranking. Currently ranked models (all 39/39): gpt-4.1, gpt-4.1-mini, gpt-4o, gpt-4o-mini, gpt-4.1-nano, grok-3-mini, llama-3.3-70b, gemini-2.5-flash. All others flagged as partial.

**No multi-turn, RAG, or long-context scenarios.** RDAB tests single-session agentic loops on structured tabular data only.

---

## Project Structure

```
realdataagentbench/
├── core/
│   ├── task.py           # Pydantic schema — validates every YAML field
│   └── registry.py       # Discovers, loads, and filters tasks
├── datasets/
│   └── generators/       # 37 synthetic generators (33 clean + 4 messy) + 6 real-data loaders
├── harness/
│   ├── tools.py          # Agent tools in a restricted namespace (run_code, get_dataframe_info, get_column_stats)
│   ├── tracer.py         # Records every step, tool call, and token count
│   ├── agent.py          # Multi-model agentic loop
│   ├── providers.py      # Unified BaseProvider — Anthropic, OpenAI, Groq, xAI, Google
│   ├── pricing.py        # Cost per 1M tokens (single source of truth)
│   └── runner.py         # Orchestrates task → dataset → agent → trace → JSON
├── scoring/
│   ├── correctness.py    # Ground truth matching with alias expansion
│   ├── code_quality.py   # Static analysis of agent-generated code
│   ├── efficiency.py     # Token and step efficiency vs. budget
│   ├── stat_validity.py  # Lexical statistical rigour signals (category-aware)
│   ├── llm_judge.py      # LLM-as-judge scorer for calibration
│   └── composite.py      # Weighted RDAB Score + ScoreCard
└── cli.py                # dab run / list / inspect / score / models
tasks/
├── eda/                  # 7 tasks
├── feature_engineering/  # 8 tasks
├── modeling/             # 8 tasks
├── statistical_inference/ # 8 tasks
└── ml_engineering/       # 8 tasks
tests/                    # 168 offline tests — no API calls required
scripts/
├── build_leaderboard.py        # outputs/ → docs/results.json (mean ± 95% CI)
├── run_uncertainty_uplift.py   # Pre-registered prompt-variant experiment (45 runs)
├── calibrate_stat_validity.py  # Lexical scorer vs LLM judge (Cohen's κ)
└── dimension_correlations.py   # Scorer-to-scorer Pearson correlation matrix
docs/
└── index.html            # GitHub Pages leaderboard (auto-rebuilt by CI)
```

---

## Roadmap

- **Done:** Task schema and harness (196 tests), 43 tasks (39 scored on the leaderboard + 4 newly-added messy-data tasks), 12 models with live leaderboard, per-run cost tracking, category-aware scorer, 6 real-data tasks, published scorer-validity calibration (lexical vs LLM judge, per-category κ/r), subprocess-isolated code execution, multi-run CI; free models + gpt-4.1 family at full 39-task CI; two-model uncertainty-uplift experiment (GPT-4.1 complete, Llama partial — model-dependent effect confirmed); stat_validity v1.5 patch (numeric-evidence check, partial credit for lexical-only matches; −0.001 to −0.034 per model across 1,356 traces)
- **In progress:** calibration κ between lexical scorer and LLM judge (v1.5 re-run pending); Llama feat_002/model_003 V1 runs (pending daily TPD reset)
- **Done (coverage):** claude-haiku-4-5 reached full 39/39 (+4 messy) coverage — the 10 remaining tasks run at n=5 (`stat_011` repeatedly hit `max_steps` without converging, a haiku token-spiral consistent with Insight 3)
- **Done (integration):** Tether + CostGuard `/replay` — production traces captured via Tether feed directly into CostGuard for RDAB-grounded cost-vs-quality comparison with 95% bootstrap CI
- **Next:** NLP, visualization, and time-series task categories; arXiv paper

---

## How to Cite

```bibtex
@software{patibandla2026rdab,
  author    = {Patibandla, Venkata Manideep},
  title     = {{RealDataAgentBench}: An Open Benchmark for Statistical Validity
               in LLM Data Science Agents},
  year      = {2026},
  url       = {https://github.com/patibandlavenkatamanideep/RealDataAgentBench},
  note      = {43 tasks (39 scored), 4-dimensional scoring, 1{,}412 runs across 12 models.}
}
```

To reproduce the full leaderboard:

```bash
git clone https://github.com/patibandlavenkatamanideep/RealDataAgentBench
cd RealDataAgentBench && pip install -e ".[dev]"
cp .env.example .env
dab run --all --model gpt-4.1 --runs 3 --temperature 0
python scripts/build_leaderboard.py
```

All dataset generators are seeded. Running with the same model and `--temperature 0` reproduces published scores within scoring tolerance.

---

## Adding a Task / Contributing

1. Create `tasks/<category>/<task_id>.yaml` — see [TASK_SPEC.md](TASK_SPEC.md)
2. Add a seeded generator in `realdataagentbench/datasets/generators/`
3. Register it in `realdataagentbench/datasets/__init__.py`
4. Add tests in `tests/` and verify `pytest tests/ -v` passes

See [CONTRIBUTING.md](CONTRIBUTING.md) for the full guide.

**→ [Submit your model's results](RESULTS_SUBMISSION.md)** — run all 39 tasks with the unmodified harness and open a PR. Community results strengthen the benchmark for everyone.

---

## The Evaluation Stack

RDAB is the benchmark layer of a three-project evaluation stack:

- **RDAB (this repo)** — benchmark methodology. 39 tasks, 4-dimensional scoring, 1,412+ runs across 12 models.
- **[CostGuard](https://github.com/patibandlavenkatamanideep/CostGuard)** — runtime layer. Applies RDAB-calibrated scoring on every proxy call; `POST /replay` replays production traces against alternate models with a 95% bootstrap CI and cost savings estimate.
- **[Tether](https://github.com/patibandlavenkatamanideep/Tether)** — capture layer. Wraps OpenAI clients and persists every production call to SQLite. Feed the resulting database into CostGuard `/replay` to answer "can I use the cheaper model?" with statistical confidence.

**CostGuard live app →** [costguard-production-3afa.up.railway.app](https://costguard-production-3afa.up.railway.app/) — upload your own CSV, run a live cost-performance analysis against any of the 12 RDAB-benchmarked models.

---

## License

MIT — see [LICENSE](LICENSE).

Built by [Venkata Manideep Patibandla](https://venkatamanideep.com/) · [LinkedIn](https://www.linkedin.com/in/manideep-analytics/) · [GitHub](https://github.com/patibandlavenkatamanideep)
