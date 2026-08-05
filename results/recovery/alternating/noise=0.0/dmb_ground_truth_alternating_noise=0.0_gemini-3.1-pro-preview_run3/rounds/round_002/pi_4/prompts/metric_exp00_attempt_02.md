# metric_exp00_attempt_02

## System Prompt

You are a psychology researcher proposing a metric in the Decision Making (Binary Features) domain.

Your goal is adversarial: propose a metric that DISCRIMINATES the two theories — i.e., its value, computed on data simulated under your advocated theory, should be as far as possible from its value computed on data simulated under the competing theory. The direction of the gap does not matter; what matters is that the two theories produce visibly different numbers on this metric. The metric is computed on the data collected from the experimental design provided in the prompt. Produce a metric where you're prediction will be much more accurate than the competing theory's prediction on human data.

Your metric is a Python function

    metric(data: pd.DataFrame) -> float

Available imports inside `metric`:
- numpy as np
- pandas as pd

The system evaluates your metric in two ways and reports the pair as `point_estimate (var=between_subject_variance)` everywhere downstream:
- `point_estimate` is `metric(data)` applied to the FULL pooled DataFrame (all subjects together) — the canonical scalar;
- `between_subject_variance` is the population variance (`ddof=0`) of `metric(subj_df)` re-applied per `subject_id`, summarising how stable the metric is across subjects. If your metric only makes sense on multi-subject data this will fall back to `n/a` and the metric is rejected (the acceptance test below cannot run without it). Prefer metrics that work both on the pooled DataFrame and on a single subject's slice.

Acceptance rule: the system simulates each theory and runs Welch's two-sample t-test on `(point_estimate_self, between_subject_variance_self, N)` vs. `(point_estimate_adv, between_subject_variance_adv, N)`, where N is the number of HUMAN subjects the experiment will actually be run with (a fixed small number, currently 25). Your metric is admitted iff the two-sided p-value is below the significance level (currently alpha=0.01). Implication: a large between-theory gap is NOT enough — if either theory's metric is also highly variable across subjects, N humans won't reliably distinguish them and the metric will be rejected. Aim for contrasts that are both large in mean AND tight per subject.

Do NOT propose metrics that are trivially true for your theory.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## CHOSEN EXPERIMENTAL DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  trial 2: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 7: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Rationale:** This design quantitatively dissociates Random Guessing from the Weighted Additive (WADD) model by presenting a systematic gradient of evidence. By varying the difference in weighted feature values from Option A dominating completely to Option B dominating completely, WADD predicts a monotonic change in choice probabilities tracking the evidence difference. In stark contrast, Random Guessing predicts a completely flat choice probability profile at exactly 0.5 across all trials, regardless of how overwhelming the evidence is for one option over the other.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Random Guessing: The data indicates that subjects in these specific experimental paradigms completely ignore all feature information and validities. Likely due to a lack of trial-by-trial feedback or low motivation, subjects simply choose between the two options with equal probability on every trial, resulting in chance-level performance across all metrics.

**Parameters:**
- dummy: [0.0, 1.0]

**`predict source code`:**
```python
def predict(parameters, state, history):
    import numpy as np
    # Reference the dummy parameter to satisfy the parameter usage constraint
    _ = float(parameters["dummy"])
    
    # Pure random guessing: uniform 50/50 probability regardless of the stimulus
    return np.array([0.5, 0.5])
```

**`policy source code`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## COMPETING THEORY
**Description:** Weighted Additive (WADD) model with non-linear validity scaling and extended lapse rate: Decision makers evaluate options by computing a weighted sum of their feature values. The weights are formed by centering the cue validities (val - 0.5) and raising their absolute values to a power gamma (preserving sign), which allows the model to interpolate between equal-weighting, proportional weighting, and non-compensatory behavior without extreme log-odds scaling. To account for the high degree of noise or chance-level behavior observed in specific paradigms, the lapse rate (epsilon) can range up to 1.0, and beta down to 0.0, allowing the model to capture completely random guessing natively.

**Parameters:**
- beta: [0.0, 20.0]
- epsilon: [0.0, 1.0]
- gamma: [0.0, 10.0]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Center validities so 0.5 gives 0 weight, avoiding discrete parameter
    base_w = val - 0.5
        
    # Signed exponentiation to handle negative base_w with fractional gamma safely
    w = np.sign(base_w) * (np.abs(base_w) ** gamma)
        
    score_a = np.sum(w * a)
    score_b = np.sum(w * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    return (1.0 - epsilon) * p_core + epsilon * 0.5
```

**`policy source code`:**
```python
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


## DATA SCHEMA
Your metric receives a tidy per-trial pandas DataFrame stacking all subjects (rows grouped by `subject_id`, in trial order). Columns:
- subject_id: Subject identifier (one row per trial per subject).
- option_a_ratings: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
- option_b_ratings: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
- response: 0 if subject chose A, 1 if subject chose B.

## IMPLEMENTATION GUARDRAILS
Any column in the schema above whose description names a list / tuple / np.ndarray (i.e. a per-trial sequence of values) holds non-scalar cells. Those cells are NOT hashable, so operations that hash row values fail with `TypeError: unhashable type: 'list'`. Treating `<seq_col>` as a placeholder for any such sequence-valued column:
- Avoid: `data.groupby('<seq_col>')`, `data['<seq_col>'].value_counts()`,     `data['<seq_col>'].nunique()`, `data['<seq_col>'].unique()` (returns     an object array but downstream `set()` / `in dict` will crash),     `set(data['<seq_col>'])`, `data['<seq_col>'].isin([...])` against list     values, or using a list cell as a dict key.
- If you need a hashable surrogate, project to one first, e.g.:
    - `data['<seq_col>_key'] = data['<seq_col>'].apply(tuple)` then group by `<seq_col>_key`
    - `data['<seq_col>_str'] = data['<seq_col>'].apply(lambda x: ''.join(map(str, x)))`
    Scalar columns (ints, floats, strings like `subject_id`, integer     responses, etc.) hash fine and can be used directly.
- Generator expressions inside function calls like `map()` or `join()` MUST be     parenthesized. For example:
    - WRONG: `map(str, int(v) for v in x)` → SyntaxError
    - RIGHT: `map(str, (int(v) for v in x))` or use a list comp: `[str(int(v)) for v in x]`
- Always verify your code is syntactically valid Python before returning it.

## METRICS YOU ALREADY TRIED AND FAILED ON
Each entry below is a metric you previously proposed in this round that did NOT discriminate the two theories at the human sample size — either it errored, its between-subject variance was unavailable, or Welch's t-test on `(self mean, self var, N)` vs. `(adv mean, adv var, N)` returned p ≥ alpha. The `outcome` line is the simulation result (means, between-subject variances, t-statistic and p-value at the human N) on the same `data_self` / `data_adv` your next metric will be evaluated on. Use the numbers to see where your hypothesised contrast collapsed — small mean gap, large per-subject variance, or both — and propose something qualitatively different. Don't repeat the same idea with cosmetic tweaks.
[0] rationale: This metric calculates the proportion of trials where the subject chose the option with the higher total number of positive expert ratings. Under the advocated Random Guessing theory, subjects ignore the ratings entirely, resulting in an expected value of exactly 0.5. Under the competing Weighted Additive (WADD) theory, since all validities are positive (>=0.5), subjects will tend to choose the option with more positive ratings, leading to a metric value significantly greater than 0.5.
metric_source:
def metric(data: pd.DataFrame) -> float:
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    a_better = a_sums > b_sums
    b_better = b_sums > a_sums
    
    chose_a = data['response'] == 0
    chose_b = data['response'] == 1
    
    correct = (a_better & chose_a) | (b_better & chose_b)
    return float(correct.mean())
outcome: self_sim=0.4979 (var=0.0025) adversary_sim=0.5315 (var=0.0047) welch_t=-1.981 p=0.0539 (N=25, alpha=0.01) -> reject

[1] rationale: This metric calculates the covariance-like product between the difference in the unweighted sum of features (Option B - Option A) and the subject's centered response (where 1 is B, 0 is A). Under Random Guessing, subjects' choices are completely uncorrelated with the features, so the expected value of this metric is exactly 0, with very tight binomial variance across subjects. Under the Weighted Additive (WADD) model, as Option B gains more positive features relative to Option A, the probability of choosing B increases monotonically. This systematic relationship will yield a significantly positive metric value, clearly separating the two theories.
metric_source:
def metric(data: pd.DataFrame) -> float:
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    diffs = b_sums - a_sums
    
    return float((diffs * (data['response'] - 0.5)).mean())
outcome: self_sim=0.0133 (var=0.0243) adversary_sim=0.1077 (var=0.0530) welch_t=-1.697 p=0.09712 (N=25, alpha=0.01) -> reject

## RESPONSE FORMAT
Return a JSON object with the following fields:
- metric: Python source defining def metric(data: pd.DataFrame) -> float.
- rationale: Reasoning behind this metric; used when interpreting results.


## Response

```json
{
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    # Identify trials where Option B dominates on the top 3 most valid features (Trials 7 & 8)\n    b_top3 = data['option_b_ratings'].apply(lambda x: x[0] == 1 and x[1] == 1 and x[2] == 1)\n    \n    # Identify trials where Option A dominates on the top 3 most valid features (Trials 1 & 2)\n    a_top3 = data['option_a_ratings'].apply(lambda x: x[0] == 1 and x[1] == 1 and x[2] == 1)\n    \n    chose_b = (data['response'] == 1).astype(float)\n    \n    # Difference in probability of choosing B when B has the best features vs when A has them\n    mean_b_when_b_best = chose_b[b_top3].mean()\n    mean_b_when_a_best = chose_b[a_top3].mean()\n    \n    # Fallback to 0.0 if for some reason a subject is missing these trials\n    if pd.isna(mean_b_when_b_best) or pd.isna(mean_b_when_a_best):\n        return 0.0\n        \n    return float(mean_b_when_b_best - mean_b_when_a_best)",
  "rationale": "To robustly separate Random Guessing from the WADD model across all its parameter regimes (especially extreme values of gamma), we focus exclusively on the trials where the evidence is overwhelmingly asymmetric. In Trials 7 and 8, Option B possesses the top 3 most valid features while Option A lacks them, making B strictly preferred by WADD regardless of whether the subject uses equal weighting (gamma=0) or heavily overweighs the first feature (high gamma). In Trials 1 and 2, Option A possesses the top 3 features. Under Random Guessing, the difference in the rate of choosing B between these two trial sets is exactly 0. Under WADD, this difference will always be strictly positive because the model's preference direction is invariant to gamma on these specific trials, thereby reducing between-subject variance and maximizing the mean gap."
}
```

## Usage

```json
{
  "prompt_token_count": 3487,
  "candidates_token_count": 527,
  "total_token_count": 8590
}
```
