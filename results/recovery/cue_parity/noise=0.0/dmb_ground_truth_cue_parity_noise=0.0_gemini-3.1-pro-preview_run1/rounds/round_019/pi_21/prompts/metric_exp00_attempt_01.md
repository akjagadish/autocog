# metric_exp00_attempt_01

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
**Validities (n_features=5):** [0.95, 0.85, 0.65, 0.55, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 3: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Rationale:** To quantitatively dissociate the Advocated Theory (Leaky Competing Accumulator) from the Competing Theory (Non-linear Feature Difference Model with Flexible Validity Centering), we exploit the fundamental difference in how they center validities. The Advocated Theory hardcodes centering at 0.5, meaning any feature with validity > 0.5 always provides positive evidence for the option that wins it. Furthermore, it evaluates features sequentially with lateral inhibition, allowing early high-validity features to lock in a choice. In contrast, the Competing Theory centers validities by a flexible parameter 'theta'. If 'theta' is high, lower-validity features receive a negative weight, actively penalizing the option that wins them. By constructing trials where Option A wins the highest-validity feature AND multiple low-validity features (e.g., F1, F4, F5) while Option B wins the intermediate features (F2, F3), the Advocated Theory predicts a robust preference for Option A due to the early F1 lead and the guaranteed positive contribution of F4 and F5. However, the Competing Theory can predict a strong preference for Option B, because a high 'theta' turns A's wins on F4 and F5 into penalties, overriding F1's advantage.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Decision-makers evaluate options using a Leaky Competing Accumulator (LCA) process, where attention shifts sequentially across features in order of their validity. Evidence for each option accumulates continuously over time, subject to information decay (leakage) and lateral inhibition. When lateral inhibition is strong, early evidence from highly valid features quickly suppresses the competing option, locking in a choice and producing non-compensatory 'Take-The-Best' behavior. Conversely, when leakage and inhibition are low, evidence from all features integrates more evenly without suppression, resulting in compensatory 'Tallying' or WADD-like behavior. This provides a unified mechanistic account for the spectrum of decision strategies without requiring explicit rule-switching.

**Parameters:**
- leak: [0.0, 2.0]
- inhibition: [0.0, 5.0]
- steps_per_feature: [1, 50]
- gamma: [0.1, 5.0]
- beta: [0.1, 20.0]
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
    
    # Sort features by validity (descending) to simulate sequential attention
    order = np.argsort(val)[::-1]
    
    leak = float(parameters["leak"])
    inhibition = float(parameters["inhibition"])
    steps_per_feature = int(float(parameters["steps_per_feature"]))
    gamma = float(parameters["gamma"])
    
    x_A, x_B = 0.0, 0.0
    dt = 0.1
    
    for idx in order:
        # Non-linear scaling of validities centered at chance
        v = max(0.0, val[idx] - 0.5) ** gamma
        I_A = a[idx] * v
        I_B = b[idx] * v
        
        # Accumulate evidence over time for the current feature
        for _ in range(steps_per_feature):
            dx_A = (I_A - leak * x_A - inhibition * x_B) * dt
            dx_B = (I_B - leak * x_B - inhibition * x_A) * dt
            
            # Rectified linear units (activations cannot be negative)
            x_A = max(0.0, x_A + dx_A)
            x_B = max(0.0, x_B + dx_B)
            
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    scores = np.array([x_A, x_B])
    
    # Softmax choice rule with numerical stability
    z = beta * scores
    z -= np.max(z)
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
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
**Description:** Non-linear Feature Difference Model with Flexible Validity Centering

**Parameters:**
- theta: [0.0, 1.0]
- gamma: [0.1, 5.0]
- beta: [0.1, 20.0]
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
    
    # Center validities with a flexible threshold rather than hardcoded 0.5
    theta = float(parameters["theta"])
    w = val - theta
    
    diff = a - b
    # Compute net evidence for option A over B
    net_ev = np.sum(w * diff)
    
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Apply non-linear value function to the net evidence (Prospect Theory style)
    score = np.sign(net_ev) * (np.abs(net_ev) ** gamma)
    
    # Create scores for A and B
    scores = np.array([score, -score])
    
    # Softmax choice rule
    z = beta * scores
    z -= np.max(z) # For numerical stability
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
[0] rationale: Measures the proportion of times Option A is chosen on Trial 1 (A=[1,0,0,1,1] vs B=[0,1,1,0,0]). The Advocated Theory (LCA) predicts a strong preference for Option A because Option A wins the highest validity feature (F1), gaining an early lead that suppresses Option B through lateral inhibition, and further benefits from positive evidence on F4 and F5. The Competing Theory, however, allows for flexible validity centering (theta). If theta is high, the lower validities of F4 and F5 become negative, effectively penalizing Option A for winning them and shifting the preference towards Option B. Thus, the proportion of A choices on this specific trial strongly discriminates the two models.
metric_source:
def metric(data: pd.DataFrame) -> float:
    is_trial_1 = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 1, 1))
    if not is_trial_1.any():
        return 0.5
    return float((data.loc[is_trial_1, 'response'] == 0).mean())
outcome: self_sim=0.5500 (var=0.0377) adversary_sim=0.4662 (var=0.0528) welch_t=+1.392 p=0.1705 (N=25, alpha=0.01) -> reject

## RESPONSE FORMAT
Return a JSON object with the following fields:
- metric: Python source defining def metric(data: pd.DataFrame) -> float.
- rationale: Reasoning behind this metric; used when interpreting results.


## Response

```json
{
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    a_tuples = data['option_a_ratings'].apply(tuple)\n    \n    t1_mask = a_tuples == (1, 0, 0, 1, 1)\n    t6_mask = a_tuples == (1, 0, 0, 1, 0)\n    \n    p_a_t1 = (data.loc[t1_mask, 'response'] == 0).mean() if t1_mask.any() else 0.5\n    p_a_t6 = (data.loc[t6_mask, 'response'] == 0).mean() if t6_mask.any() else 0.5\n    \n    return float(p_a_t1 + p_a_t6)",
  "rationale": "This metric evaluates the sum of the probabilities of choosing Option A in Trial 1 and Trial 6. In the Competing Theory (Flexible Validity Centering), the net evidence for Option A in Trial 1 is mathematically exactly the negative of the net evidence for Option A in Trial 6, regardless of the validity centering parameter 'theta'. Due to the symmetric softmax choice rule, the sum of choice probabilities for Option A across these two trials is constrained to be exactly 1.0 (with minimal variance strictly due to binomial noise). In contrast, the Advocated Theory (LCA) processes features sequentially and uses non-linear accumulation with lateral inhibition; because Option A wins the highest validity feature (F1) in both trials, it gets an early head start that can lock in choices for A in both cases, leading to an expected sum significantly different from 1.0."
}
```

## Usage

```json
{
  "prompt_token_count": 3877,
  "candidates_token_count": 388,
  "total_token_count": 8489
}
```
