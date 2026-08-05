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

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  trial 2: A=[1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  trial 4: A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0]
  trial 5: A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]
  trial 6: A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 7: A=[0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 8: A=[0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  trial 9: A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  trial 10: A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  trial 11: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 12: A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]

**Rationale:** To dissociate pure Take-The-Best (TTB) from Noisy-Perception TTB, we vary the number of tied cues that precede the first discriminating cue. Pure TTB stops at the first discriminating cue and ignores all others, predicting a constant choice probability (1 - epsilon/2) regardless of how many cues were tied beforehand. In contrast, Noisy-Perception TTB assumes that cue values can be misperceived. A tied cue has a probability of being falsely perceived as discriminating, which would cause the search to stop prematurely and inject random noise. Consequently, Noisy-Perception TTB predicts a systematic decay in choice certainty (probabilities pulling closer to 0.5) as the number of preceding tied cues increases. By including trials where the first discrimination occurs at cue 1, 2, 3, 4, or 5 (with all subsequent cues tied), we can cleanly isolate this false-discrimination effect from other compensatory mechanisms.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



## ADVOCATED THEORY
**Description:** Decision-makers use a 'Noisy-Perception Take-The-Best' heuristic. They search through cues in descending order of validity, stopping at the first cue that appears to discriminate between the options. However, their perception of each option's feature value is subject to independent noise: with probability p_error, a feature's value (0 or 1) is misread. Consequently, multiple lower-validity cues can cumulatively influence the choice if earlier high-validity cues are misperceived as tied. The perception error is restricted to be very low, ensuring the model remains predominantly non-compensatory, while a decoupled lapse rate accounts for baseline errors.

**Parameters:**
- p_error: [0.0, 0.1]
- epsilon: [0.0, 0.25]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Order features by validity in descending order
    order = np.argsort(-validities)
    
    p_e = float(parameters["p_error"])
    epsilon = float(parameters["epsilon"])
    
    P_A = 0.0
    P_B = 0.0
    P_rem = 1.0
    
    # Search through features in descending order of validity
    for idx in order:
        val_a = a[idx]
        val_b = b[idx]
        
        # Probabilities of perceived cue values given true cue values
        if val_a > val_b:
            p_a_wins = (1.0 - p_e) ** 2
            p_b_wins = p_e ** 2
        elif val_b > val_a:
            p_a_wins = p_e ** 2
            p_b_wins = (1.0 - p_e) ** 2
        else:  # val_a == val_b
            p_a_wins = p_e * (1.0 - p_e)
            p_b_wins = p_e * (1.0 - p_e)
            
        p_tie = 1.0 - p_a_wins - p_b_wins
        
        P_A += P_rem * p_a_wins
        P_B += P_rem * p_b_wins
        P_rem *= p_tie
        
    # If all features tie, guess randomly
    P_A += P_rem * 0.5
    P_B += P_rem * 0.5
    
    p_core = np.array([P_A, P_B])
    
    # Blend with uniform lapse
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
```

**`policy source code`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)
```


## COMPETING THEORY
**Description:** People use a non-compensatory, lexicographic heuristic known as 'Take-The-Best' (TTB) to make decisions. Instead of integrating all available information (as in weighted additive models) or counting all positive features (as in tallying), decision-makers search through features sequentially in descending order of their validity. The search stops at the very first feature that discriminates between the two options (i.e., one option possesses the feature and the other does not). The option that wins on this single discriminating cue is chosen deterministically, and all remaining lower-validity features are completely ignored. If no features discriminate between the options, the decision-maker guesses randomly. Response noise is modeled purely as a lapse rate (epsilon) where the subject occasionally makes a random guess instead of executing the TTB strategy.

**Parameters:**
- epsilon: [0.0, 0.5]
- validities: validities

**`predict source code`:**
```python
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Take-The-Best expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Order features by validity in descending order
    order = np.argsort(-validities)
    
    # Default to guessing if all features tie
    p_core = np.array([0.5, 0.5])
    
    # Search through features in descending order of validity
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    
    # Blend deterministic choice with uniform lapse
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])
```

**`policy source code`:**
```python
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
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
  "metric_source": "def metric(data: pd.DataFrame) -> float:\n    import numpy as np\n    \n    a_ratings = np.array(data['option_a_ratings'].tolist())\n    b_ratings = np.array(data['option_b_ratings'].tolist())\n    responses = np.array(data['response'])\n    \n    # Find first discriminating cue index for each trial\n    diff = a_ratings - b_ratings\n    abs_diff = np.abs(diff)\n    disc_idx = np.argmax(abs_diff, axis=1)\n    \n    # TTB prediction: if a > b (diff > 0), predict A (0); else predict B (1)\n    first_diff = diff[np.arange(len(diff)), disc_idx]\n    ttb_pred = np.where(first_diff > 0, 0, 1)\n    \n    correct = (responses == ttb_pred).astype(float)\n    \n    # Compare accuracy on trials where discrimination happens early vs late\n    early_mask = (disc_idx == 0) | (disc_idx == 1)\n    late_mask = (disc_idx == 3) | (disc_idx == 4)\n    \n    if np.sum(early_mask) == 0 or np.sum(late_mask) == 0:\n        return 0.0\n        \n    early_acc = np.mean(correct[early_mask])\n    late_acc = np.mean(correct[late_mask])\n    \n    return float(early_acc - late_acc)\n",
  "rationale": "Pure Take-The-Best stops at the first discriminating cue and ignores all preceding ties, meaning its choice accuracy relative to the TTB prediction should be constant regardless of whether the first discriminating cue is cue 1 or cue 5. In contrast, the Noisy-Perception TTB model assumes that ties can be misperceived as discriminating. As the number of preceding ties increases (i.e., when discrimination happens later, like at cue 4 or 5), there is a higher cumulative probability of prematurely stopping due to perceptual noise, which pushes the choice probabilities closer to 0.5. Therefore, the difference in TTB-adherence between early-discrimination trials (cues 1 and 2) and late-discrimination trials (cues 4 and 5) will be near zero for pure TTB, but significantly positive for Noisy-Perception TTB."
}
```

## Usage

```json
{
  "prompt_token_count": 3702,
  "candidates_token_count": 581,
  "total_token_count": 6410
}
```
