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
Probabilistic Cue Selection (Random Cue) posits that decision-makers do not deterministically use the most valid cue (like Take-The-Best) nor do they integrate all cues simultaneously (like WADD). Instead, on each trial, they sample a single cue with a probability proportional to its subjective validity. They then choose the option favored by that sampled cue, guessing uniformly if the sampled cue ties. This single-cue sampling process naturally generates probabilistic choices across trials, producing choice shares near 0.50 for conflict trials where different cues favor different options, without relying on extreme softmax noise.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    n_features = stim.shape[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    w = np.asarray(parameters["weights"], dtype=float)
    
    # Subjective validities used as sampling weights
    subj_weights = val * w
    sum_w = np.sum(subj_weights)
    
    if sum_w <= 1e-9:
        p_core = np.array([0.5, 0.5])
    else:
        p_cue = subj_weights / sum_w
        a, b = stim[0], stim[1]
        
        p_a = 0.0
        for j in range(n_features):
            if a[j] > b[j]:
                p_a += p_cue[j]
            elif a[j] == b[j]:
                p_a += p_cue[j] * 0.5
                
        p_core = np.array([p_a, 1.0 - p_a])
        
    epsilon = float(parameters["epsilon"])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_4
Equal Weights (Tallying)

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    
    # Count the number of positive features for each option
    tally_a = np.sum(stim[0])
    tally_b = np.sum(stim[1])
    
    if tally_a > tally_b:
        scores = np.array([1.0, 0.0])
    elif tally_b > tally_a:
        scores = np.array([0.0, 1.0])
    else:
        # Guess randomly if there is a tie
        return np.array([0.5, 0.5])
        
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the binary tally score
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Independent lapse
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.7, 0.55, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 4: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate Probabilistic Cue Selection (Random Cue) from Equal Weights (Tallying), we exploit Tallying's complete insensitivity to cue validities. Tallying simply counts the number of positive features for each option and strictly prefers the one with the higher count, applying softmax noise to the binary outcome. Random Cue, however, samples cues proportionally to their subjective validities (validity * weight) and chooses the option favored by the sampled cue. By presenting trials where one option has fewer positive cues but those cues possess significantly higher validities, Tallying will consistently predict a preference for the option with more positive cues, whereas Random Cue will predict a preference (or at least a much higher choice probability) for the option supported by fewer, more valid cues.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
In every trial of the design, Option B has a strictly higher simple tally of positive features than Option A. Consequently, the Equal Weights (Tallying) model will consistently predict choices for Option B, leading to a near-zero proportion of choosing Option A (driven only by lapse rates). In contrast, Probabilistic Cue Selection (Random Cue) evaluates options probabilistically based on cue validities. Because Option A possesses the most valid cues (e.g., cue 1 and cue 2) in many trials, Random Cue will predict a significantly higher proportion of choices for Option A. Thus, the overall proportion of choosing Option A robustly discriminates the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    return float(np.mean(data['response'] == 0))


### RESULTS
- Predicted under pi_3 (simulated): 0.4548 (var=0.0037)
- Predicted under pi_4 (simulated): 0.3387 (var=0.0148)
- Observed on real data: 0.5075 (var=0.0019)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 3: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 7: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 8: A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]

**Rationale:** To quantitatively dissociate Equal Weights (Tallying) from Probabilistic Cue Selection (Random Cue), we exploit Tallying's strict reliance on the count of positive features and its complete disregard for cue validities. By using a feature environment with highly skewed validities (e.g., two highly valid cues and three less valid cues), we can create 'conflict' trials where one option has fewer positive cues but a higher total validity sum (e.g., Option A has 2 highly valid cues, Option B has 3 low-validity cues). Tallying predicts a deterministic-like preference for the option with more cues (Option B), whereas Random Cue predicts a preference for the option with higher total validity (Option A). Furthermore, we include 'tie' trials where both options have the same number of positive cues but drastically different validity sums. Tallying predicts exact random guessing (50/50) on these trials, while Random Cue predicts strong preferences based on the validities.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Tallying bases its decision solely on whether Option A has more positive cues than Option B, entirely ignoring the magnitude of the difference. In Trial 4 (A has 4 cues, B has 1) and Trial 7 (A has 3, B has 2), Tallying strictly prefers A and predicts the exact same probability of choosing A for both trials. Thus, P(A|T4) - P(A|T7) = 0. Similarly, in Trial 1 and Trial 2, Option B has exactly one more cue than A, so Tallying predicts the exact same probability of choosing A for both trials, making P(A|T1) - P(A|T2) = 0. The combined contrast (P(A|T4) - P(A|T7)) + (P(A|T1) - P(A|T2)) is mathematically guaranteed to have an expected value of 0 for Tallying, completely eliminating parameter-driven variance. For Random Cue, however, choices are highly sensitive to cue validities. The cues in T4 strongly favor A compared to T7, and T1 favors A more than T2. This yields an expected value of ~0.34 for Random Cue, creating an extremely large and reliable contrast.

Source:
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    m1 = a_str == '11000'
    m2 = a_str == '10100'
    m4 = a_str == '01111'
    m7 = a_str == '00111'
    
    def get_p_a(mask):
        subset = data.loc[mask, 'response']
        if len(subset) == 0:
            return 0.5
        return float((subset == 0).mean())
        
    p1 = get_p_a(m1)
    p2 = get_p_a(m2)
    p4 = get_p_a(m4)
    p7 = get_p_a(m7)
    
    return float((p4 - p7) + (p1 - p2))

### RESULTS
- Predicted under pi_3 (simulated): 0.2583 (var=0.1245)
- Predicted under pi_4 (simulated): -0.0233 (var=0.0692)
- Observed on real data: 0.0133 (var=0.1054)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def get_cue1_winner(row):
        if row['option_a_ratings'][0] > row['option_b_ratings'][0]:
            return 0
        elif row['option_b_ratings'][0] > row['option_a_ratings'][0]:
            return 1
        return -1
    
    cue1_winners = data.apply(get_cue1_winner, axis=1)
    valid_trials = cue1_winners != -1
    if not valid_trials.any():
        return 0.5
    
    return np.mean(data.loc[valid_trials, 'response'] == cue1_winners[valid_trials])
```

**Observed (real) value:** 0.5071 (var=0.0028)
**Predicted under pi_3:** 0.4753 (var=0.0043)
**Predicted under pi_4:** 0.4778 (var=0.0027)

### Experiment 4
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    ttb_matches = 0
    conflict_trials = 0
    
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == (1, 0, 0, 0) and b == (0, 1, 1, 1):
            if resp == 0: ttb_matches += 1
            conflict_trials += 1
        elif a == (0, 1, 1, 1) and b == (1, 0, 0, 0):
            if resp == 1: ttb_matches += 1
            conflict_trials += 1
        elif a == (0, 1, 0, 0) and b == (0, 0, 1, 1):
            if resp == 0: ttb_matches += 1
            conflict_trials += 1
        elif a == (0, 0, 1, 1) and b == (0, 1, 0, 0):
            if resp == 1: ttb_matches += 1
            conflict_trials += 1
            
    if conflict_trials == 0:
        return 0.5
    return float(ttb_matches / conflict_trials)
```

**Observed (real) value:** 0.4822 (var=0.0067)
**Predicted under pi_3:** 0.4017 (var=0.0165)
**Predicted under pi_4:** 0.3261 (var=0.0239)

### Experiment 5
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    data = data.copy()
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    data['chose_a'] = (data['response'] == 0).astype(float)
    
    # We focus on the '3v1' trials where WADD predicts near-deterministic choices
    target_trials = ['0111', '1110', '1011']
    df_target = data[data['a_str'].isin(target_trials)]
    
    if df_target.empty:
        return 0.5
        
    # Calculate the proportion of A choices per subject and trial type
    grouped = df_target.groupby(['subject_id', 'a_str'])['chose_a'].mean()
    
    # Consistency is how far the choice proportion is from 0.5 (i.e., max(P(A), P(B)))
    consistency = np.maximum(grouped, 1.0 - grouped)
    
    return float(consistency.mean())
```

**Observed (real) value:** 0.6489 (var=0.0031)
**Predicted under pi_3:** 0.7252 (var=0.0057)
**Predicted under pi_4:** 0.6970 (var=0.0079)

### Experiment 6
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Objective validities used in the experiment
    v = np.array([0.9, 0.8, 0.7, 0.6, 0.5])
    
    # Reconstruct the feature matrices
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    # Calculate objective scores and differences
    score_a = a_ratings @ v
    score_b = b_ratings @ v
    diff = score_a - score_b
    
    # Select "easy" trials with a large score difference (abs(diff) >= 0.65)
    # In this design, this cleanly isolates Trials 7, 9, and 10.
    mask = np.abs(diff) >= 0.65
    
    if not np.any(mask):
        return 0.5
        
    # Determine if the subject chose the option with the higher objective score
    is_correct = ((diff > 0) & (data['response'] == 0)) | ((diff < 0) & (data['response'] == 1))
    
    # Return the simple accuracy on these easy trials
    return float(is_correct[mask].mean())
```

**Observed (real) value:** 0.5233 (var=0.0124)
**Predicted under pi_3:** 0.6092 (var=0.0121)
**Predicted under pi_4:** 0.6708 (var=0.0215)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, neither Probabilistic Cue Selection (Theory 1) nor Equal Weights / Tallying (Theory 2) perfectly captures the observed data, but they each capture different aspects. In Experiment 2, the observed metric is near zero (0.0133), which strongly aligns with Tallying's prediction (-0.0233) that subjects are largely insensitive to validity differences when the count of positive cues is identical. However, in Experiment 1, subjects choose Option A (which has fewer but more valid cues) around 50% of the time. Tallying predicts a strong preference for Option B (metric ~0.33), failing to capture that subjects do weigh validities enough to offset a simple tally deficit. Random Cue captures some validity sensitivity but fails on Experiment 2. This suggests subjects are using a strategy that integrates both the number of cues and their validities, but perhaps with significant noise.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Weighted Additive Model (WADD)' to replace Probabilistic Cue Selection. Unlike pure Tallying (which ignores validities) and Random Cue (which samples a single cue), WADD integrates all available features by computing a sum of cue values weighted by their subjective validities. This allows the model to predict indifference (near 0.5) when a higher tally is perfectly offset by lower validities (as in Experiment 1), while still capturing the nuanced sensitivity (or lack thereof, depending on the softmax temperature) across different trial types. Ensure the model includes a softmax temperature and a lapse rate to accommodate the high degree of noise observed in the data (many metrics hover near 0.5)."
}
```

## Usage

```json
{
  "prompt_token_count": 6522,
  "candidates_token_count": 380,
  "total_token_count": 8462
}
```
