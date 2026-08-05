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

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 3: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 4: A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]

**Rationale:** This design quantitatively dissociates Sequential Evidence Accumulation (SEA) from the Weighted Additive (WADD) theory by exploiting their fundamentally different mechanisms for scaling evidence. WADD scales validities via exponentiation (gamma), which relies on the ratio between validities. Because the ratio between adjacent validities increases as validities get smaller (e.g., 0.75/0.65 > 0.85/0.75), WADD naturally becomes *more* non-compensatory (TTB-like) at lower levels of the cue hierarchy. In contrast, SEA uses an absolute difference threshold (theta) on unscaled validities. Because the absolute values of the validities decrease down the hierarchy, SEA naturally becomes *less* non-compensatory at lower levels, as single cues are no longer large enough to cross the fixed threshold. By pitting a single discriminating cue against the remaining lower cues at different levels of the hierarchy (e.g., Cue 2 vs Cues 3-5, and Cue 3 vs Cues 4-5), SEA predicts non-compensatory choices at the top of the hierarchy and compensatory choices at the bottom. WADD predicts the exact opposite pattern, making them highly distinguishable.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Sequential Evidence Accumulation Theory: Decision-makers sample cues sequentially in order of their validity, accumulating evidence for each option. The accumulation process stops as soon as the absolute difference in evidence between the two options reaches a subject-specific threshold. A low threshold mimics non-compensatory heuristics like Take-The-Best by stopping at the first discriminating cue, while a high threshold mimics compensatory strategies like Weighted Additive (WADD) by integrating all available cues. This natural stopping rule generates variable choice probabilities across different conflict geometries, naturally capturing moderate variance across stimuli without requiring non-linear scaling of validities.

**Parameters:**
- theta: [0.0, 1.25]
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.2]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    theta = float(parameters["theta"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Sort cues by validity descending
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    score_a = 0.0
    score_b = 0.0
    
    for j in cue_order:
        score_a += val[j] * a[j]
        score_b += val[j] * b[j]
        
        diff = abs(score_a - score_b)
        # Stop if threshold is reached AND there is a strict difference (to avoid stopping on ties if theta is 0)
        if diff >= theta and diff > 1e-9:
            break
            
    scores = np.array([score_a, score_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    import pandas as pd\n    \n    a_seq = data['option_a_ratings'].apply(tuple)\n    b_seq = data['option_b_ratings'].apply(tuple)\n    \n    t1_a = (1, 0, 0, 0, 0)\n    t1_b = (0, 1, 1, 1, 1)\n    \n    t3_a = (1, 1, 1, 0, 0)\n    t3_b = (1, 1, 0, 1, 1)\n    \n    t1_mask1 = (a_seq == t1_a) & (b_seq == t1_b)\n    t1_mask2 = (a_seq == t1_b) & (b_seq == t1_a)\n    \n    t3_mask1 = (a_seq == t3_a) & (b_seq == t3_b)\n    t3_mask2 = (a_seq == t3_b) & (b_seq == t3_a)\n    \n    p_t1 = 0.0\n    n_t1 = t1_mask1.sum() + t1_mask2.sum()\n    if n_t1 > 0:\n        chose_a_t1 = (t1_mask1 & (data['response'] == 0)) | (t1_mask2 & (data['response'] == 1))\n        p_t1 = chose_a_t1.sum() / n_t1\n        \n    p_t3 = 0.0\n    n_t3 = t3_mask1.sum() + t3_mask2.sum()\n    if n_t3 > 0:\n        chose_a_t3 = (t3_mask1 & (data['response'] == 0)) | (t3_mask2 & (data['response'] == 1))\n        p_t3 = chose_a_t3.sum() / n_t3\n        \n    return float(p_t1 - p_t3)\n",
  "rationale": "WADD predicts that the non-compensatory choice (A) is more likely in Trial 3 than Trial 1, because the ratio of adjacent validities increases down the cue hierarchy (0.75/0.65 > 0.95/0.85). Thus, WADD naturally becomes more non-compensatory at lower levels of the hierarchy. In contrast, SEA predicts the opposite: the non-compensatory choice (A) is more likely in Trial 1 than Trial 3, because the absolute difference in evidence decreases down the hierarchy, making it less likely to cross the stopping threshold (theta) for lower-ranked cues. The metric computes the difference in the probability of choosing option A between Trial 1 and Trial 3. SEA predicts a positive difference, while WADD predicts a negative difference."
}
```

## Usage

```json
{
  "prompt_token_count": 3311,
  "candidates_token_count": 710,
  "total_token_count": 8834
}
```
