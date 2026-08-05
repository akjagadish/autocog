# metric_exp00_attempt_00

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
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=5):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  trial 3: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Rationale:** This design quantitatively dissociates Generalized WADD from Dual-Process Strategy Selection by pitting constant absolute WADD evidence differences against decreasing top-cue validities. Across trials, the top discriminating cue shifts down the hierarchy (from Cue 1 to Cue 2 to Cue 3), while the linear WADD sum difference favoring the opposing option remains strictly constant. Dual-Process Strategy Selection relies on the absolute validity of the top discriminating cue to probabilistically trigger the non-compensatory Take-The-Best (TTB) strategy; therefore, it predicts choices will become less TTB-like (more compensatory) as the top cue moves down the hierarchy and its validity drops. In contrast, Generalized WADD scales validities via exponentiation, which depends on the ratio between validities. Because the ratio between adjacent validities increases down the hierarchy (e.g., 0.75/0.65 > 0.95/0.85), Generalized WADD predicts decisions will inherently become MORE TTB-like at lower levels of the hierarchy. These diametrically opposed predictions provide a strong quantitative dissociation.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



## ADVOCATED THEORY
**Description:** People make decisions by integrating all available information rather than stopping at the first discriminating cue or simply counting features. According to the Weighted Additive (WADD) theory, decision-makers evaluate each option by computing a sum of its features, weighted by the subjective validity of each feature. However, people may non-linearly amplify the importance of highly valid cues. To capture this, validities are exponentiated by a scaling parameter and then normalized, allowing the model to smoothly interpolate between highly compensatory (Tallying-like) and non-compensatory (TTB-like) decision strategies without shrinking the overall scale of the evidence. Choice probabilities are generated via a softmax function over the weighted sums, with an independent lapse rate for random guessing.

**Parameters:**
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- gamma: [1.0, 30.0]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    val = val ** gamma
    val = val / np.sum(val)
    
    a, b = stim[0], stim[1]
    
    # Compute weighted sum of features for each option
    score_a = np.sum(val * a)
    score_b = np.sum(val * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the WADD scores
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)
```

**`policy source code`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## COMPETING THEORY
**Description:** Dual-Process Strategy Selection Theory: Decision-makers probabilistically select between a non-compensatory heuristic (Take-The-Best) and a compensatory strategy (Weighted Additive, WADD) on a trial-by-trial basis. The probability of employing the non-compensatory heuristic is a logistic function of the absolute validity of the highest-ranking discriminating cue. When the top discriminating cue is highly valid, subjects are highly likely to rely solely on it (TTB). However, when the top discriminating cue is weak, confidence in the heuristic drops, and subjects fall back to integrating all available information (WADD).

**Parameters:**
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- theta: [0.0, 1.0]
- tau: [1.0, 100.0]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    theta = float(parameters["theta"])
    tau = float(parameters["tau"])
    
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    top_cue = None
    for j in cue_order:
        if a[j] != b[j]:
            top_cue = j
            break
            
    if top_cue is None:
        p_mix = np.array([0.5, 0.5])
    else:
        v_top = val[top_cue]
        
        # Probability of using TTB is a logistic function of the top cue's validity
        p_ttb_use = 1.0 / (1.0 + np.exp(-tau * (v_top - theta)))
        
        # Take-The-Best (TTB) prediction
        winner_ttb = 0 if a[top_cue] > b[top_cue] else 1
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        z_ttb = beta * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
        # Weighted Additive (WADD) prediction
        score_a = np.sum(val * a)
        score_b = np.sum(val * b)
        scores_wadd = np.array([score_a, score_b])
        z_wadd = beta * (scores_wadd - np.max(scores_wadd))
        e_wadd = np.exp(z_wadd)
        p_wadd = e_wadd / np.sum(e_wadd)
        
        # Mix the two strategies based on the top cue validity
        p_mix = p_ttb_use * p_ttb + (1.0 - p_ttb_use) * p_wadd
        
    # Apply lapse rate
    return (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])
```

**`policy source code`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
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
(none yet)

## RESPONSE FORMAT
Return a JSON object with the following fields:
- metric: Python source defining def metric(data: pd.DataFrame) -> float.
- rationale: Reasoning behind this metric; used when interpreting results.


## Response

```json
{
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    # Identify Trial 1 and Trial 3 based on option A's ratings\n    t1_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 0, 0))\n    t3_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 0, 0))\n    \n    if t1_mask.sum() == 0 or t3_mask.sum() == 0:\n        return 0.0\n        \n    # response is 0 for A, 1 for B. So mean() is the proportion of choosing B.\n    # We want the difference in proportion of choosing A: P(A | Trial 3) - P(A | Trial 1)\n    # Which is (1 - m3) - (1 - m1) = m1 - m3\n    m1 = data[t1_mask]['response'].mean()\n    m3 = data[t3_mask]['response'].mean()\n    \n    return float(m1 - m3)",
  "rationale": "This metric calculates the difference in the probability of choosing Option A (the TTB prediction) between Trial 3 (where the top cue is Cue 3) and Trial 1 (where the top cue is Cue 1). The Dual-Process theory predicts this difference will be negative, as reliance on the TTB heuristic drops when the top cue's absolute validity decreases. In contrast, the Generalized WADD theory predicts this difference will be positive (or near zero), because the exponentiated validities create larger relative differences (ratios) between adjacent cues lower in the hierarchy, making decisions more TTB-like."
}
```

## Usage

```json
{
  "prompt_token_count": 3545,
  "candidates_token_count": 418,
  "total_token_count": 6263
}
```
