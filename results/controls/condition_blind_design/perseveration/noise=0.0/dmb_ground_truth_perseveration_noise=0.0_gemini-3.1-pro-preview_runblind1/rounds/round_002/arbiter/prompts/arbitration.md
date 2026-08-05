# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
Decision-makers evaluate options using a Weighted Additive (WADD) strategy. Instead of relying on a single best cue (like Take The Best) or ignoring cue importance (like Tallying), individuals integrate all available features by weighting each feature according to its validity. The overall value of an option is the sum of its validity-weighted features. Choices are then made probabilistically by comparing these weighted sums, with response consistency governed by a softmax temperature parameter and a base lapse rate. A highly restricted temperature parameter prevents over-sensitivity to small differences in the weighted sums, matching the near-chance behavior of human subjects.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Calculate validity-weighted sums for both options
    score_a = np.sum(a * val)
    score_b = np.sum(b * val)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=float)
    probabilities /= probabilities.sum()  # Ensure valid probabilities
    return np.random.choice(len(probabilities), p=probabilities)

## THEORY 2 — pi_4
Noisy Take The Best: Decision-makers use a lexicographic heuristic (Take The Best), checking features in descending order of validity and stopping at the first feature that discriminates between options. However, human application of this rule is highly noisy. A heavily restricted inverse temperature parameter accounts for the empirical observation that subjects' choices on these trials hover near chance level (0.50-0.55), rather than the highly deterministic choices (0.85+) predicted by standard TTB.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Sort cues by validity descending; stable sort preserves original order on ties
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        elif b[j] > a[j]:
            winner = 1
            break
            
    if winner is None:
        return np.ones(2) / 2.0
        
    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(2) / 2.0)

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=4):** [0.95, 0.55, 0.65, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[1, 0, 1, 0]  B=[1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1]  B=[1, 1, 0, 1]
  trial 3: A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  trial 4: A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  trial 5: A=[0, 1, 0, 1]  B=[1, 1, 1, 0]
  trial 6: A=[1, 0, 0, 1]  B=[1, 0, 1, 0]
  trial 7: A=[0, 0, 0, 1]  B=[0, 0, 1, 1]
  trial 8: A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  trial 9: A=[1, 1, 0, 1]  B=[1, 1, 1, 0]
  trial 10: A=[0, 0, 0, 0]  B=[0, 1, 0, 1]
  trial 11: A=[0, 1, 0, 1]  B=[1, 0, 0, 1]
  trial 12: A=[1, 0, 0, 0]  B=[1, 1, 0, 0]
  trial 13: A=[0, 1, 1, 1]  B=[1, 1, 1, 0]
  trial 14: A=[0, 1, 0, 1]  B=[0, 0, 1, 1]
  trial 15: A=[1, 1, 1, 1]  B=[0, 1, 1, 1]
  trial 16: A=[0, 0, 0, 1]  B=[0, 0, 1, 0]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
In this experimental design, both TTB and WADD predict the exact same winning option on every single trial. However, the models differ fundamentally in how choice probabilities are determined. Under Noisy TTB, the 'evidence' for the winner is always exactly 1.0 (since it stops at the first discriminating cue), meaning the predicted probability of choosing the winner is constant across all trials. Under WADD, the evidence for the winner varies continuously based on the difference in weighted sums between the two options. By calculating the accuracy (choosing the favored option) on trials where the WADD score difference is high (>=0.8) and subtracting the accuracy on trials where the WADD score difference is low (<=0.4), we isolate this structural difference. WADD predicts a substantial positive difference, whereas TTB predicts a difference of zero.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    val = np.array([0.95, 0.55, 0.65, 0.55])
    
    # Extract options as 2D arrays
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    # Calculate WADD scores
    scores_a = np.dot(a_ratings, val)
    scores_b = np.dot(b_ratings, val)
    
    diffs = np.abs(scores_a - scores_b)
    
    # Determine if the subject chose the option with the higher WADD score
    # (Note: For this specific design, TTB and WADD agree on the winner for all 16 trials)
    chose_a = (data['response'] == 0).values
    correct = ((scores_a > scores_b) & chose_a) | ((scores_b > scores_a) & ~chose_a)
    
    # Contrast trials with a large difference in WADD scores vs a small difference
    high_diff = diffs >= 0.8
    low_diff = diffs <= 0.4
    
    if np.sum(high_diff) == 0 or np.sum(low_diff) == 0:
        return 0.0
        
    return float(np.mean(correct[high_diff]) - np.mean(correct[low_diff]))

### RESULTS
- Predicted under pi_3 (simulated): 0.0819 (var=0.0158)
- Predicted under pi_4 (simulated): 0.0102 (var=0.0104)
- Observed on real data: -0.0933 (var=0.1024)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=4):** [0.95, 0.87, 0.89, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[1, 0, 1, 1]  B=[0, 1, 0, 0]
  trial 2: A=[0, 1, 0, 0]  B=[1, 0, 1, 0]
  trial 3: A=[1, 0, 1, 0]  B=[0, 1, 1, 0]
  trial 4: A=[0, 0, 1, 0]  B=[1, 1, 0, 0]
  trial 5: A=[1, 1, 1, 1]  B=[1, 0, 1, 1]
  trial 6: A=[0, 0, 1, 0]  B=[0, 1, 0, 0]
  trial 7: A=[1, 0, 1, 1]  B=[0, 1, 0, 0]
  trial 8: A=[0, 0, 0, 1]  B=[1, 0, 0, 0]
  trial 9: A=[1, 1, 0, 1]  B=[0, 1, 0, 0]
  trial 10: A=[0, 1, 0, 1]  B=[0, 1, 0, 0]
  trial 11: A=[0, 1, 1, 0]  B=[0, 1, 0, 0]
  trial 12: A=[0, 1, 0, 0]  B=[1, 0, 1, 0]
  trial 13: A=[1, 0, 1, 0]  B=[0, 1, 0, 0]
  trial 14: A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  trial 15: A=[1, 1, 1, 1]  B=[0, 1, 0, 0]
  trial 16: A=[0, 1, 0, 1]  B=[0, 0, 1, 1]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
TTB implies that as long as a cue discriminates between options, the decision is made with a constant degree of confidence (since the score difference is always 1.0 for a winner). Thus, TTB predicts the same choice accuracy regardless of the WADD-weighted sum difference. WADD, on the other hand, predicts that choice accuracy scales with the difference in expected value between the two options. This metric computes the difference in accuracy between trials with a large WADD score difference (> 1.0) and trials with a small WADD score difference (< 0.5). TTB predicts a value near 0, while WADD predicts a positive value.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.87, 0.89, 0.55])
    
    acc_large = []
    acc_small = []
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        score_a = np.sum(a * val)
        score_b = np.sum(b * val)
        
        diff = abs(score_a - score_b)
        
        if score_a > score_b:
            correct = 1 if row['response'] == 0 else 0
        else:
            correct = 1 if row['response'] == 1 else 0
            
        if diff > 1.0:
            acc_large.append(correct)
        elif diff < 0.5:
            acc_small.append(correct)
            
    if not acc_large or not acc_small:
        return 0.0
        
    return float(np.mean(acc_large) - np.mean(acc_small))

### RESULTS
- Predicted under pi_3 (simulated): 0.1828 (var=0.0289)
- Predicted under pi_4 (simulated): 0.0112 (var=0.0189)
- Observed on real data: -0.0240 (var=0.3594)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 1, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 1]  B=[0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # The validities are [0.95, 0.72, 0.73, 0.55]
    # Thus, the descending order of cue validities for Take The Best is:
    # Feature 0 (0.95), Feature 2 (0.73), Feature 1 (0.72), Feature 3 (0.55)
    cue_order = [0, 2, 1, 3]
    matches = []
    
    for a_vals, b_vals, resp in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        a = np.array(a_vals)
        b = np.array(b_vals)
        
        # Isolate trials where Tallying predicts a tie (equal number of feature wins)
        if np.sum(a > b) == np.sum(b > a):
            # Take The Best will still make a deterministic prediction based on the first discriminating cue
            for j in cue_order:
                if a[j] > b[j]:
                    matches.append(1.0 if resp == 0 else 0.0)
                    break
                elif b[j] > a[j]:
                    matches.append(1.0 if resp == 1 else 0.0)
                    break
                    
    return float(np.mean(matches)) if matches else 0.5
```

**Observed (real) value:** 0.5500 (var=0.0600)
**Predicted under pi_3:** 0.5583 (var=0.0103)
**Predicted under pi_4:** 0.5433 (var=0.0108)

### Experiment 4
**Design**
  A=[1, 1, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 0, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[0, 0, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[0, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 1, 1, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    score = 0.0
    count = 0
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        a_list = list(a)
        b_list = list(b)
        # Trial 1: Tallying ties, TTB predicts A (0)
        if a_list == [1, 1, 0, 1] and b_list == [0, 1, 1, 1]:
            score += (1 if r == 0 else 0)
            count += 1
        # Trial 2: Tallying ties, TTB predicts B (1)
        elif a_list == [0, 1, 1, 0] and b_list == [1, 0, 1, 0]:
            score += (1 if r == 1 else 0)
            count += 1
        # Trial 9: Tallying predicts A, TTB predicts B (1)
        elif a_list == [0, 1, 0, 1] and b_list == [0, 0, 1, 0]:
            score += (1 if r == 1 else 0)
            count += 1
            
    if count == 0:
        return 0.5
    return float(score / count)
```

**Observed (real) value:** 0.5333 (var=0.0267)
**Predicted under pi_3:** 0.4856 (var=0.0137)
**Predicted under pi_4:** 0.5456 (var=0.0123)

### Experiment 5
**Design**
  A=[1, 1, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 1, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 0, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 1, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    val = np.array([0.95, 0.6, 0.87, 0.55])
    
    wadd_match = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        tally_a = np.sum(a > b)
        tally_b = np.sum(b > a)
        
        if tally_a == tally_b:
            wadd_a = np.sum(a * val)
            wadd_b = np.sum(b * val)
            if wadd_a > wadd_b:
                wadd_match.append(1 if row['response'] == 0 else 0)
            elif wadd_b > wadd_a:
                wadd_match.append(1 if row['response'] == 1 else 0)
                
    return float(np.mean(wadd_match)) if len(wadd_match) > 0 else 0.5
```

**Observed (real) value:** 0.4900 (var=0.0624)
**Predicted under pi_3:** 0.5425 (var=0.0123)
**Predicted under pi_4:** 0.5417 (var=0.0140)

### Experiment 6
**Design**
  A=[0, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 0]
  A=[0, 0, 1, 0]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    is_t2 = (a_str == '0110') & (b_str == '1001')
    is_t16 = (a_str == '1011') & (b_str == '0111')
    
    t2_wadd_choices = (data.loc[is_t2, 'response'] == 1).sum()
    t16_wadd_choices = (data.loc[is_t16, 'response'] == 0).sum()
    
    total_trials = is_t2.sum() + is_t16.sum()
    
    if total_trials == 0:
        return 0.5
        
    return float((t2_wadd_choices + t16_wadd_choices) / total_trials)
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_3:** 0.5550 (var=0.0238)
**Predicted under pi_4:** 0.5167 (var=0.0244)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed data consistently contradicts the Weighted Additive (WADD) strategy (Theory 1). In Experiment 1, subjects actually showed a negative difference in accuracy between high and low WADD-score-difference trials, which WADD strongly predicts should be positive. In Experiment 2, the observed effect was near zero (or slightly negative), again failing to support WADD's prediction that larger expected value differences lead to more deterministic choices. Theory 2 (Noisy Take The Best) performs slightly better by predicting near-zero effects on WADD-specific metrics, but still fails to predict the negative effect in Experiment 1 and hovers near chance across most metrics. The fact that subjects' behavior consistently sits at chance level when evaluating validity-based differences suggests they are likely ignoring the validities entirely. A simpler heuristic, such as Tallying (Equal Weights), where subjects simply count the number of positive features for each option regardless of their validities, would better explain the insensitivity to validity weights and the near-chance behavior on trials designed to separate WADD and TTB.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Tallying' (or Equal Weights) theory. In this theory, subjects ignore the explicit cue validities and simply count the number of positive features for each option. They choose the option with the highest total number of positive features. If both options have the same number of positive features, they guess randomly. This theory fundamentally breaks from both WADD and TTB by assuming validities are discarded, which naturally explains the near-chance performance on validity-dependent metrics and the lack of sensitivity to WADD score differences."
}
```

## Usage

```json
{
  "prompt_token_count": 7736,
  "candidates_token_count": 371,
  "total_token_count": 9104
}
```
