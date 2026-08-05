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
**Validities (n_features=5):** [0.95, 0.9, 0.85, 0.6, 0.55]

**Trial pairs (n=7):**
  trial 1: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 3: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Rationale:** To quantitatively dissociate the Advocated Theory (a Strategy Selection/Mixture model of TTB, Tallying, and WADD) from the Competing Theory (Sequential Evidence Accumulation with a stopping threshold), we exploit the fact that Sequential Accumulation only maintains a running sum of unweighted differences (+1 or -1) in validity order. If the threshold is 1, it acts exactly like Take-The-Best (TTB). If the threshold is high, it falls back to Pure Tallying. Consequently, if TTB and Tallying both agree on an option, Sequential Accumulation MUST choose that option, regardless of its threshold parameter. The Advocated Theory, however, includes WADD as a sub-model, which weights features by their log-odds validities. By selecting a specific set of validities (e.g., 0.95, 0.90, 0.85, 0.60, 0.55), we can construct trials where the single best feature (F1) and two weak features (F4, F5) support Option A, while two strong intermediate features (F2, F3) support Option B. In this scenario, TTB chooses A (wins F1) and Tallying chooses A (3 wins vs 2). Thus, the Competing Theory strictly predicts A. However, the log-odds sum for B (F2+F3) outweighs A (F1+F4+F5), meaning WADD chooses B. The Advocated Theory can therefore predict a substantial probability of choosing B, achieving a sharp qualitative and quantitative dissociation.

**Computed schedule:** 7 unique pairs × 13 reps = 91 trials per subject.



## ADVOCATED THEORY
**Description:** Heuristic Toolbox / Strategy Selection Theory with Graded Sub-models: Decision-makers possess a repertoire of distinct decision heuristics (Take-The-Best, Tallying, and Weighted Additive). Instead of assuming pure determinism within each heuristic, each strategy produces graded choice probabilities via a softmax rule applied to its internal evidence (e.g., validity of the discriminating cue for TTB, cue sum for Tallying, log-odds sum for WADD) using a shared choice temperature. Individuals probabilistically select one of these softened heuristics on any given trial.

**Parameters:**
- w_ttb: [0.0, 50.0]
- w_tally: [0.0, 50.0]
- w_wadd: [0.0, 50.0]
- beta_choice: [0.1, 10.0]
- epsilon: [0.0, 0.5]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    w_ttb = float(parameters["w_ttb"])
    w_tally = float(parameters["w_tally"])
    w_wadd = float(parameters["w_wadd"])
    beta_choice = float(parameters["beta_choice"])
    epsilon = float(parameters["epsilon"])
    
    # Normalize weights to get mixture probabilities for the strategies
    total_w = w_ttb + w_tally + w_wadd + 1e-9
    p_ttb = w_ttb / total_w
    p_tally = w_tally / total_w
    p_wadd = w_wadd / total_w
    
    # Strategy 1: Take-The-Best (TTB) Evidence
    order = np.argsort(val)[::-1]
    ttb_score_a, ttb_score_b = 0.0, 0.0
    for idx in order:
        if a[idx] > b[idx]:
            ttb_score_a, ttb_score_b = val[idx], 0.0
            break
        elif b[idx] > a[idx]:
            ttb_score_a, ttb_score_b = 0.0, val[idx]
            break
            
    z_ttb = beta_choice * np.array([ttb_score_a, ttb_score_b])
    z_ttb -= np.max(z_ttb)
    e_ttb = np.exp(z_ttb)
    ttb_probs = e_ttb / np.sum(e_ttb)
    ttb_a, ttb_b = ttb_probs[0], ttb_probs[1]
            
    # Strategy 2: Tallying (Equal Weights) Evidence
    sum_a = np.sum(a)
    sum_b = np.sum(b)
    
    z_tally = beta_choice * np.array([sum_a, sum_b])
    z_tally -= np.max(z_tally)
    e_tally = np.exp(z_tally)
    tally_probs = e_tally / np.sum(e_tally)
    tally_a, tally_b = tally_probs[0], tally_probs[1]
        
    # Strategy 3: Weighted Additive (WADD) Evidence
    val_clipped = np.clip(val, 0.501, 0.999)
    w = np.log(val_clipped / (1.0 - val_clipped))
    score_a = np.sum(a * w)
    score_b = np.sum(b * w)
    
    z_wadd = beta_choice * np.array([score_a, score_b])
    z_wadd -= np.max(z_wadd)
    e_wadd = np.exp(z_wadd)
    wadd_probs = e_wadd / np.sum(e_wadd)
    wadd_a, wadd_b = wadd_probs[0], wadd_probs[1]
        
    # Probabilistic mixture of discrete strategy predictions
    p_A_core = p_ttb * ttb_a + p_tally * tally_a + p_wadd * wadd_a
    p_B_core = p_ttb * ttb_b + p_tally * tally_b + p_wadd * wadd_b
    p_core = np.array([p_A_core, p_B_core])
    
    # Apply lapse rate
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
**Description:** Decision-makers use a Sequential Evidence Accumulation strategy with a stopping rule. They inspect features one by one in descending order of their validity, maintaining a running sum of the differences between the options. If the absolute accumulated evidence reaches or exceeds a specific threshold, they stop and make a choice based on that evidence. If the threshold is not reached, they evaluate all features and decide based on the final tally. This allows the model to smoothly transition between Take-The-Best (low threshold) and Tallying (high threshold) behaviors.

**Parameters:**
- threshold: [0.0, 3.0]
- beta: [0.1, 15.0]
- epsilon: [0.0, 0.5]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Order features by validity descending
    order = np.argsort(val)[::-1]
    
    threshold = float(parameters["threshold"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    diff = a - b
    accumulated_evidence = 0.0
    
    for idx in order:
        accumulated_evidence += diff[idx]
        if abs(accumulated_evidence) >= threshold and abs(accumulated_evidence) > 0:
            break
            
    scores = np.array([accumulated_evidence, -accumulated_evidence])
    
    z = beta * scores
    z -= np.max(z)
    p_core = np.exp(z) / np.sum(np.exp(z))
    
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    import pandas as pd\n    \n    a_tuples = data['option_a_ratings'].apply(tuple)\n    b_tuples = data['option_b_ratings'].apply(tuple)\n    \n    mask1 = (a_tuples == (1, 0, 0, 1, 1)) & (b_tuples == (0, 1, 1, 0, 0))\n    mask2 = (a_tuples == (0, 1, 1, 0, 0)) & (b_tuples == (1, 0, 0, 1, 1))\n    \n    wadd_choices = 0\n    wadd_choices += (data.loc[mask1, 'response'] == 1).sum()\n    wadd_choices += (data.loc[mask2, 'response'] == 0).sum()\n    \n    total = mask1.sum() + mask2.sum()\n    \n    if total == 0:\n        return 0.0\n    return float(wadd_choices / total)",
  "rationale": "This metric calculates the proportion of times the subject chooses the option favored exclusively by the Weighted Additive (WADD) strategy in a specific pair of trials. Specifically, for the pair [1, 0, 0, 1, 1] vs. [0, 1, 1, 0, 0], both Take-The-Best and Tallying favor the first option. Furthermore, the Competing Theory's Sequential Accumulation mechanism also strictly prefers the first option, regardless of its threshold parameter (the accumulated evidence for the first option never drops below 0 and ends at +1). However, the WADD submodel in the Advocated Theory strongly favors the second option [0, 1, 1, 0, 0] because the combined log-odds of features 2 and 3 outweigh features 1, 4, and 5. Therefore, the Advocated Theory predicts a significantly higher choice rate for [0, 1, 1, 0, 0] than the Competing Theory, which will only choose it via random lapses."
}
```

## Usage

```json
{
  "prompt_token_count": 4106,
  "candidates_token_count": 505,
  "total_token_count": 7417
}
```
