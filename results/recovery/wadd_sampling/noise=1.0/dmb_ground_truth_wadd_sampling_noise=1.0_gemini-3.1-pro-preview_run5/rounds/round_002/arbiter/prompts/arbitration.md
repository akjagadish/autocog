# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_4" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_4" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_4
When faced with complex multi-attribute choices without trial-by-trial feedback, subjects experience cognitive overload. Instead of systematically integrating cue validities and feature vectors, they abandon structured decision strategies and resort to random guessing. Choice behavior is driven entirely by this stochasticity, with only a potential slight bias toward one spatial position (e.g., Option A or Option B) over the other.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    # Under cognitive overload, subjects ignore the state (features) and just guess.
    # The choice probability is determined only by an intrinsic side bias.
    p_b = float(parameters.get('side_bias', 0.5))
    p_a = 1.0 - p_b
    return np.array([p_a, p_b])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)

## THEORY 2 — pi_3
People compare options by computing a compensatory overall value for each option. This is done by summing the features of each option weighted by their respective validities (Weighted Additive rule). Because empirical behavior in these experiments is highly stochastic (near random guessing), choice is subject to significant softmax noise and lapse rates. Narrowing the inverse temperature bounds forces the model to capture this high level of noise.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != stim.shape[1]:
        raise ValueError("Length of validities must match number of features.")

    a, b = stim[0], stim[1]
    
    # Compute weighted sum of features for each option
    a_score = np.sum(a * val)
    b_score = np.sum(b * val)
    scores = np.array([a_score, b_score])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_4)

### DESIGN
**Validities (n_features=4):** [0.9, 0.8, 0.7, 0.6]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0]  B=[1, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  trial 4: A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  trial 5: A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  trial 6: A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  trial 7: A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  trial 8: A=[0, 0, 0, 1]  B=[1, 1, 1, 0]

**Rationale:** To dissociate the Cognitive Overload theory (which predicts choice probabilities are completely invariant to stimulus features and driven only by a constant side bias) from the Weighted Additive theory (which predicts that choice probabilities, despite being noisy, will systematically track the weighted feature differences between options). By presenting trials with maximal and intermediate differences in weighted sums favoring either Option A or Option B, we can observe whether the empirical choice rates shift in the direction of the superior option (supporting WADD) or remain flat across all trial types (supporting Cognitive Overload).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
The Cognitive Overload theory predicts that subjects ignore feature values and guess based on a constant side bias. Therefore, the probability of choosing Option B should be completely independent of whether Option B is objectively better than Option A. The Weighted Additive (WADD) theory predicts that subjects' choices will be positively correlated with the difference in weighted feature sums. This metric computes the difference in the choice rate of Option B between trials where Option B is substantially better than Option A and trials where Option A is substantially better. Under Cognitive Overload, this difference should be zero; under WADD, it should be significantly positive.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    val = np.array([0.9, 0.8, 0.7, 0.6])
    
    def score_diff(row):
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        return np.sum(b * val) - np.sum(a * val)
        
    diffs = data.apply(score_diff, axis=1)
    
    b_better = data['response'][diffs > 0.5]
    a_better = data['response'][diffs < -0.5]
    
    m_b = b_better.mean() if len(b_better) > 0 else 0.5
    m_a = a_better.mean() if len(a_better) > 0 else 0.5
    
    return float(m_b - m_a)

### RESULTS
- Predicted under pi_4 (simulated): 0.0039 (var=0.0327)
- Predicted under pi_3 (simulated): 0.2217 (var=0.0711)
- Observed on real data: -0.0500 (var=0.0218)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=6):** [1.0, 0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 2: A=[0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 3: A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0]
  trial 4: A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0]
  trial 5: A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  trial 7: A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  trial 8: A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  trial 9: A=[1, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  trial 10: A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate the highly-stochastic Weighted Additive (WADD) theory from the Cognitive Overload (random guessing) theory, we must test whether choice probabilities remain completely flat across trials or whether they track the weighted feature differences, even if dampened by high noise. We use 6 features to create a wide spectrum of weighted score differences between Option A and Option B, ranging from subtle (+0.6) to extreme (+4.5), and their exact mirrors. WADD predicts a monotonic relationship between the score difference and the probability of choosing A, whereas Cognitive Overload predicts a completely flat choice rate driven only by a constant side bias.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
The Weighted Additive (WADD) theory predicts that the probability of choosing Option A increases as the WADD score of A relative to B increases. A linear regression slope between the score difference and the binary choice captures this sensitivity. Under WADD, this slope will be positive (even if attenuated by high noise). Under Cognitive Overload, subjects guess randomly with a fixed side bias, completely ignoring the features, yielding an expected slope of exactly zero.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([1.0, 0.9, 0.8, 0.7, 0.6, 0.5])
    A = np.array(data['option_a_ratings'].tolist())
    B = np.array(data['option_b_ratings'].tolist())
    
    # Calculate the difference in WADD scores between Option A and Option B
    score_diff = A.dot(validities) - B.dot(validities)
    
    # 1 if A was chosen, 0 if B was chosen
    chose_a = 1.0 - data['response'].values
    
    if np.var(score_diff) == 0:
        return 0.0
    
    # Calculate the linear slope of choosing A as a function of the score difference
    slope, _ = np.polyfit(score_diff, chose_a, 1)
    return float(slope)

### RESULTS
- Predicted under pi_4 (simulated): 0.0010 (var=0.0005)
- Predicted under pi_3 (simulated): 0.0504 (var=0.0011)
- Observed on real data: 0.0014 (var=0.0003)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    def ttb_predict(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]:
                return 0
            elif a[i] < b[i]:
                return 1
        return 0.5
        
    ttb_choices = data.apply(ttb_predict, axis=1)
    matches = (data['response'] == ttb_choices)
    return float(matches.mean())
```

**Observed (real) value:** 0.5050 (var=0.0019)
**Predicted under pi_4:** 0.4925 (var=0.0032)
**Predicted under pi_3:** 0.4608 (var=0.0041)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 1, 0, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        # Only consider trials where Tallying has a strict preference
        if a_wins > b_wins:
            tally_choice = 0
            matches.append(int(row['response'] == tally_choice))
        elif b_wins > a_wins:
            tally_choice = 1
            matches.append(int(row['response'] == tally_choice))
            
    if not matches:
        return 0.5
    return float(np.mean(matches))

```

**Observed (real) value:** 0.5107 (var=0.0040)
**Predicted under pi_4:** 0.5063 (var=0.0043)
**Predicted under pi_3:** 0.5367 (var=0.0061)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    diff = a_mat - b_mat
    
    # TTB prediction: sign of the first non-zero difference
    abs_diff = np.abs(diff)
    first_diff_idx = np.argmax(abs_diff, axis=1)
    first_diff_val = diff[np.arange(len(diff)), first_diff_idx]
    ttb_pred = np.where(first_diff_val > 0, 0, 1)
    
    # WADD prediction: based on weighted sum
    a_score = np.dot(a_mat, val)
    b_score = np.dot(b_mat, val)
    wadd_pred = np.where(a_score > b_score, 0, 1)
    
    # Identify conflict trials where TTB and WADD make opposite predictions
    conflict = (ttb_pred != wadd_pred) & (first_diff_val != 0)
    
    if not np.any(conflict):
        return 0.5
        
    responses = data['response'].values
    # Calculate the proportion of choices that align with TTB on conflict trials
    matches = (responses[conflict] == ttb_pred[conflict])
    
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5038 (var=0.0039)
**Predicted under pi_4:** 0.5231 (var=0.0205)
**Predicted under pi_3:** 0.4553 (var=0.0041)

### Experiment 6
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    A = np.vstack(data['option_a_ratings'].values)
    B = np.vstack(data['option_b_ratings'].values)
    
    score_A = A.dot(val)
    score_B = B.dot(val)
    
    wadd_choice = (score_B > score_A).astype(int)
    
    return float(np.mean(data['response'].values == wadd_choice))
```

**Observed (real) value:** 0.5018 (var=0.0029)
**Predicted under pi_4:** 0.4891 (var=0.0030)
**Predicted under pi_3:** 0.5747 (var=0.0043)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed data shows that subjects' choices are extremely noisy and barely deviate from random guessing. Metrics measuring structured decision strategies like Weighted Additive (WADD), Take-The-Best (TTB), or Tallying all hover around 0.5 (or 0 for difference/slope metrics). Theory 1 (Cognitive Overload / Random Guessing) consistently captures this near-zero effect size. Theory 2 (WADD with high noise) consistently overpredicts the degree to which subjects use the weighted validities to make choices, even with high softmax noise and lapse rates. Since WADD is clearly failing to capture the extreme flatness of the data, Theory 2 should be replaced.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace Theory 2 with a 'Tallying under Overload' or 'Equal Weights' theory. Instead of integrating complex cue validities (which causes the WADD model to overpredict sensitivity to score differences), subjects might completely ignore the validities and fall back to a simpler heuristic: just counting the number of positive features (1s) for each option. To capture the near-random behavior observed empirically, this simple tallying process must still be coupled with a very high lapse rate or extreme softmax noise. This provides a structured but highly simplified alternative to pure random guessing."
}
```

## Usage

```json
{
  "prompt_token_count": 6007,
  "candidates_token_count": 301,
  "total_token_count": 7432
}
```
