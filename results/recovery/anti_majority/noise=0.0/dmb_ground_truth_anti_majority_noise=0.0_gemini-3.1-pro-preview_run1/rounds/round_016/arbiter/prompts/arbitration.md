# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_18" and "pi_14") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_18" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_14" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_18
Sequential Unique Feature Comparison with Reference Point: Decision-makers simplify choices by cancelling out shared features. They then evaluate the remaining unique features sequentially, starting from the most valid feature. Evidence is accumulated relative to a subjective reference point (threshold), meaning highly valid features provide positive evidence while weak features below the reference point act as penalties. The process stops as soon as the difference in accumulated evidence between the options exceeds a subjective stopping threshold.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    rho = float(parameters["rho"])
    theta = float(parameters["theta"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Cancel out shared features
    shared = (a > 0) & (b > 0)
    unique_a = a.copy()
    unique_a[shared] = 0
    unique_b = b.copy()
    unique_b[shared] = 0
    
    # Transform validities
    v_trans = val ** gamma
    
    # Find unique validity values among active features, sorted descending
    active_mask = (unique_a > 0) | (unique_b > 0)
    
    score_a = 0.0
    score_b = 0.0
    
    if np.any(active_mask):
        unique_vals = np.unique(v_trans[active_mask])[::-1]
        
        for v in unique_vals:
            # Add all features with this validity
            mask_v = (v_trans == v)
            
            # Evidence contributed is relative to the reference point (rho)
            evidence = v - rho
            
            score_a += np.sum(unique_a[mask_v]) * evidence
            score_b += np.sum(unique_b[mask_v]) * evidence
            
            # Stop sequential evaluation if evidence difference exceeds threshold
            if abs(score_a - score_b) >= theta:
                break
            
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_14
Thresholded Unique Features with Spread Penalty: Decision-makers simplify choices by cancelling out shared features, then evaluate the unique features relative to a subjective validity threshold. Features above the threshold provide positive evidence, while those below act as penalties. These values are integrated additively, but options with multiple unique features suffer a conflict penalty proportional to the spread (max - min) of their thresholded validities. This penalizes options with a wide variance in their unique features while strictly preserving shared-feature cancellation.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Model expects a (2, n_features) stimulus.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    rho = float(parameters["rho"])
    lambda_penalty = float(parameters["lambda_penalty"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Cancel out shared features
    shared = (a > 0) & (b > 0)
    unique_a = a.copy()
    unique_a[shared] = 0
    unique_b = b.copy()
    unique_b[shared] = 0
    
    # Transform validities and apply subjective threshold
    v_trans = val ** gamma
    w = v_trans - rho
    
    def get_score(x):
        active_w = w[x > 0]
        if len(active_w) == 0:
            return 0.0
        
        # Additive integration of thresholded evidence
        base_score = np.sum(active_w)
        
        # Spread penalty applied if there are multiple unique features
        if len(active_w) > 1:
            conflict_penalty = lambda_penalty * (np.max(active_w) - np.min(active_w))
            return base_score - conflict_penalty
            
        return base_score
        
    score_a = get_score(unique_a)
    score_b = get_score(unique_b)
    
    scores = np.array([score_a, score_b])
    
    # Softmax choice rule
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_18)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  trial 3: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 4: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 5: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  trial 8: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Rationale:** To quantitatively dissociate the Advocated Theory (Sequential Unique Feature Comparison with Reference Point) from the Competing Theory (Thresholded Unique Features with Spread Penalty), we exploit their fundamentally different integration mechanisms for unique features. The Advocated Theory evaluates features sequentially from highest to lowest validity and stops as soon as the evidence difference exceeds a threshold (theta). This means it can completely ignore lower-validity unique features once a decision is reached. The Competing Theory evaluates all unique features additively but applies a penalty proportional to their spread (max - min). We design trials pitting an option with a single high-validity feature against an option with one very high and one very low validity feature. The Advocated Theory, due to its sequential stopping rule, will often evaluate only the highest validity feature and ignore the lowest one. The Competing Theory will evaluate both, and because of the large spread, heavily penalize the option with two features, leading to a strong preference for the single-feature option. We also include trials pitting a single high-validity feature against a coalition of moderately high-validity features to contrast the sequential stopping (favoring the single feature) with additive integration (favoring the coalition).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the probability of choosing the option with ratings [1, 0, 0, 0, 1] when it is paired against options that lack the highest validity feature but have moderate ones (like [0, 1, 0, 0, 0] or [0, 1, 1, 0, 0]). The Advocated Theory's sequential stopping rule leads it to heavily favor the [1, 0, 0, 0, 1] option because it evaluates the highest-validity feature (v1) first and often stops before reaching the lowest-validity feature (v5). In contrast, the Competing Theory integrates all unique features and severely penalizes the [1, 0, 0, 0, 1] option due to the large spread (v1 - v5) between its validities, leading to a much lower choice probability.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Convert rating lists to string representations for easy comparison
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # We track how often the option with ratings [1, 0, 0, 0, 1] is chosen
    is_A_10001 = (data['A_str'] == '10001')
    is_B_10001 = (data['B_str'] == '10001')
    
    # Only consider trials where the *other* option is either [0, 1, 0, 0, 0] or [0, 1, 1, 0, 0]
    # These correspond to Trial 1 and Trial 7 from the design.
    valid_other = ['01000', '01100']
    
    mask_A = is_A_10001 & data['B_str'].isin(valid_other)
    mask_B = is_B_10001 & data['A_str'].isin(valid_other)
    
    choices_10001 = 0
    total_trials = 0
    
    # If A is [1, 0, 0, 0, 1], response == 0 means it was chosen
    choices_10001 += (data.loc[mask_A, 'response'] == 0).sum()
    total_trials += mask_A.sum()
    
    # If B is [1, 0, 0, 0, 1], response == 1 means it was chosen
    choices_10001 += (data.loc[mask_B, 'response'] == 1).sum()
    total_trials += mask_B.sum()
    
    if total_trials == 0:
        return 0.5
        
    return float(choices_10001 / total_trials)

### RESULTS
- Predicted under pi_18 (simulated): 0.6033 (var=0.0598)
- Predicted under pi_14 (simulated): 0.1767 (var=0.0260)
- Observed on real data: 0.3067 (var=0.0344)

## EXPERIMENT 2 (proposed by pi_14)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  trial 2: A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 4: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 5: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  trial 6: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 7: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate the Advocated Theory (Thresholded Unique Features with Spread Penalty) from the Competing Theory (Sequential Unique Feature Comparison with Reference Point), we exploit their fundamentally different integration mechanisms for unique features. The Competing Theory evaluates features sequentially from highest to lowest validity and stops as soon as the evidence difference exceeds a threshold (theta). This means it can completely ignore lower-validity unique features once a decision is reached. The Advocated Theory evaluates all unique features additively but applies a penalty proportional to their spread (max - min). We design trials pitting an option with a single high-validity feature against an option with one very high and one very low validity feature. The Competing Theory, due to its sequential stopping rule, will often evaluate only the highest validity feature and ignore the lowest one, choosing the option with the highest validity feature. The Advocated Theory will evaluate both, and because of the large spread, heavily penalize the option with two features, leading to a strong preference for the single-feature option. We also include trials pitting a single high-validity feature against a coalition of moderately high-validity features to contrast the sequential stopping (favoring the single feature) with additive integration (favoring the coalition).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Trials 1, 4, and 7 present option A with the highest validity feature but also low validity features, creating a large spread in feature validities. Option B lacks the highest validity feature but has a smaller or zero spread. The Competing Theory, using sequential evaluation, will often stop after evaluating A's highest validity feature and choose A. The Advocated Theory, however, will apply a strong spread penalty to A, significantly reducing its value and making B more likely to be chosen. The metric calculates the choice proportion for Option A on these specific trials to maximally differentiate the models.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    mask1 = (a_str == '10001') & (b_str == '01000')
    mask4 = (a_str == '10001') & (b_str == '01100')
    mask7 = (a_str == '10011') & (b_str == '01100')
    
    target_mask = mask1 | mask4 | mask7
    if not target_mask.any():
        return 0.5
        
    return float((data.loc[target_mask, 'response'] == 0).mean())

### RESULTS
- Predicted under pi_18 (simulated): 0.5894 (var=0.0449)
- Predicted under pi_14 (simulated): 0.1867 (var=0.0206)
- Observed on real data: 0.1278 (var=0.0107)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    diff = a_ratings - b_ratings
    ttb_winner = np.zeros(len(data))
    
    for i in range(len(data)):
        winner = -1
        for j in range(5):
            if diff[i, j] > 0:
                winner = 0
                break
            elif diff[i, j] < 0:
                winner = 1
                break
        ttb_winner[i] = winner
        
    return float(np.mean(data['response'].values == ttb_winner))
```

**Observed (real) value:** 0.7675 (var=0.0218)
**Predicted under pi_18:** 0.7804 (var=0.0452)
**Predicted under pi_14:** 0.7602 (var=0.0175)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    strict_mask = a_wins != b_wins
    if not np.any(strict_mask):
        return 0.5
        
    tally_preds = (b_wins > a_wins).astype(int)
    responses = np.array(data['response'].tolist())
    
    match = (tally_preds[strict_mask] == responses[strict_mask])
    return float(np.mean(match))
```

**Observed (real) value:** 0.2552 (var=0.0312)
**Predicted under pi_18:** 0.1776 (var=0.0305)
**Predicted under pi_14:** 0.3014 (var=0.0318)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_choice = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_choice = 0
                break
            elif b[i] > a[i]:
                ttb_choice = 1
                break
                
        if ttb_choice != -1:
            matches.append(1 if resp == ttb_choice else 0)
            
    return float(np.mean(matches)) if matches else 0.5
```

**Observed (real) value:** 0.6317 (var=0.0095)
**Predicted under pi_18:** 0.7629 (var=0.0437)
**Predicted under pi_14:** 0.7217 (var=0.0250)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Calculate the total number of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Focus on diagnostic trials where one option has more positive features than the other.
    # In this specific design, these are exactly the trials where the single highest-validity
    # discriminating cue favors the option with FEWER total features.
    mask = sum_a != sum_b
    if not mask.any():
        return 0.5
        
    filtered_data = data[mask]
    sum_a_filt = sum_a[mask]
    sum_b_filt = sum_b[mask]
    
    # Determine which option has the greater number of positive features
    # 0 for A, 1 for B
    compensatory_choice = (sum_b_filt > sum_a_filt).astype(int)
    
    # Calculate the proportion of choices aligning with the compensatory (WADD-like) option
    match = (filtered_data['response'] == compensatory_choice).mean()
    return float(match)

```

**Observed (real) value:** 0.2888 (var=0.0207)
**Predicted under pi_18:** 0.2425 (var=0.0670)
**Predicted under pi_14:** 0.1997 (var=0.0245)

### Experiment 7
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # The validities are strictly decreasing from cue 0 to cue 3.
    # So the Take-The-Best (TTB) choice is simply determined by the first cue 
    # (from index 0 to 3) where the two options differ.
    def get_ttb_choice(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(4):
            if a[i] > b[i]: return 0
            if b[i] > a[i]: return 1
        return 0
        
    data['ttb_choice'] = data.apply(get_ttb_choice, axis=1)
    data['is_ttb'] = (data['response'] == data['ttb_choice']).astype(float)
    
    # Create a hashable string representation of the trial pair to group by
    data['trial_str'] = data.apply(lambda x: ''.join(map(str, x['option_a_ratings'])) + '_' + ''.join(map(str, x['option_b_ratings'])), axis=1)
    
    # Calculate the proportion of TTB-consistent choices for each unique trial type
    trial_means = data.groupby('trial_str')['is_ttb'].mean()
    
    # Return the standard deviation of these proportions across the 10 trial types
    return float(trial_means.std())
```

**Observed (real) value:** 0.3309 (var=0.0110)
**Predicted under pi_18:** 0.0668 (var=0.0105)
**Predicted under pi_14:** 0.2511 (var=0.0107)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['a_cues'] = data['option_a_ratings'].apply(sum)
    data['b_cues'] = data['option_b_ratings'].apply(sum)
    
    def ttb_favors_a(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]: return True
            if b[i] > a[i]: return False
        return False

    data['ttb_a'] = data.apply(ttb_favors_a, axis=1)
    
    df_conflict = data[data['ttb_a']].copy()
    
    high_mask = df_conflict['b_cues'] >= 3
    low_mask = df_conflict['b_cues'] <= 2
    
    p_high = df_conflict.loc[high_mask, 'response'].mean()
    p_low = df_conflict.loc[low_mask, 'response'].mean()
    
    if pd.isna(p_high): p_high = 0.5
    if pd.isna(p_low): p_low = 0.5
    
    return float(p_high - p_low)
```

**Observed (real) value:** -0.1823 (var=0.0238)
**Predicted under pi_18:** -0.0184 (var=0.0107)
**Predicted under pi_14:** 0.1129 (var=0.0217)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    # Identify trials where Option A's features are a strict subset of Option B's features
    is_subset = np.all(a_ratings <= b_ratings, axis=1) & (np.sum(a_ratings, axis=1) < np.sum(b_ratings, axis=1))
    
    subset_data = data[is_subset]
    if len(subset_data) == 0:
        return 0.5
        
    # Return the proportion of times Option A was chosen
    return float(np.mean(subset_data['response'] == 0))
```

**Observed (real) value:** 0.8678 (var=0.0153)
**Predicted under pi_18:** 0.6678 (var=0.0840)
**Predicted under pi_14:** 0.7411 (var=0.0548)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    b_sum = data['option_b_ratings'].apply(sum)
    p_b_3 = data.loc[b_sum == 3, 'response'].mean()
    p_b_2 = data.loc[b_sum == 2, 'response'].mean()
    return float(p_b_3 - p_b_2)
```

**Observed (real) value:** -0.1200 (var=0.0258)
**Predicted under pi_18:** -0.0234 (var=0.0063)
**Predicted under pi_14:** -0.0116 (var=0.0155)

### Experiment 11
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    A = np.stack(data['option_a_ratings'].values)
    B = np.stack(data['option_b_ratings'].values)
    
    # Determine TTB choice (first discriminating cue)
    diff = A - B
    idx = np.argmax(np.abs(diff), axis=1)
    ttb_choice = np.where(diff[np.arange(len(diff)), idx] == 1, 0, 1)
    
    # Determine Averaging choice
    sum_a = np.sum(A, axis=1)
    sum_b = np.sum(B, axis=1)
    
    avg_a = np.zeros(len(A))
    mask_a = sum_a > 0
    avg_a[mask_a] = np.sum(A[mask_a] * val, axis=1) / sum_a[mask_a]
    
    avg_b = np.zeros(len(B))
    mask_b = sum_b > 0
    avg_b[mask_b] = np.sum(B[mask_b] * val, axis=1) / sum_b[mask_b]
    
    avg_choice = np.where(avg_a > avg_b, 0, np.where(avg_b > avg_a, 1, -1))
    
    # Filter trials where TTB and Averaging disagree
    disagree_mask = (avg_choice != -1) & (ttb_choice != avg_choice)
    
    if not np.any(disagree_mask):
        return 0.5
        
    responses = data['response'].values[disagree_mask]
    ttb_choices = ttb_choice[disagree_mask]
    
    return float(np.mean(responses == ttb_choices))

```

**Observed (real) value:** 0.1572 (var=0.0102)
**Predicted under pi_18:** 0.4892 (var=0.0835)
**Predicted under pi_14:** 0.1542 (var=0.0224)

### Experiment 12
**Design**
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float((data['response'] == 0).mean())
```

**Observed (real) value:** 0.1454 (var=0.0162)
**Predicted under pi_18:** 0.3444 (var=0.0878)
**Predicted under pi_14:** 0.1571 (var=0.0082)

### Experiment 13
**Design**
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 1, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option A has the highest-validity feature (index 0) and Option B does not.
    a_has_best = data['option_a_ratings'].apply(lambda x: x[0] == 1)
    b_has_best = data['option_b_ratings'].apply(lambda x: x[0] == 1)
    mask = a_has_best & ~b_has_best
    
    if mask.sum() == 0:
        return 0.0
        
    # Return the proportion of times the subject chose Option B (response == 1)
    # despite Option A having the best possible feature.
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.7428 (var=0.0066)
**Predicted under pi_18:** 0.4739 (var=0.0168)
**Predicted under pi_14:** 0.7394 (var=0.0075)

### Experiment 14
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    extreme_chosen = 0
    total = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        idx_a = a.index(1) if 1 in a else len(a)
        idx_b = b.index(1) if 1 in b else len(b)
        
        if idx_a < idx_b:
            if resp == 0:
                extreme_chosen += 1
            total += 1
        elif idx_b < idx_a:
            if resp == 1:
                extreme_chosen += 1
            total += 1
            
    return float(extreme_chosen / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.1758 (var=0.0096)
**Predicted under pi_18:** 0.6500 (var=0.0383)
**Predicted under pi_14:** 0.1758 (var=0.0269)

### Experiment 15
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option A has the highest validity feature (index 0)
    # but also has at least one other feature, creating high variance.
    # Option B in the design always lacks the highest validity feature in these trials.
    is_target_trial = data['option_a_ratings'].apply(lambda x: x[0] == 1 and sum(x) > 1)
    target_data = data[is_target_trial]
    
    if len(target_data) == 0:
        return 0.0
        
    # Return the proportion of times Option A was chosen (response == 0)
    return (1.0 - target_data['response']).mean()
```

**Observed (real) value:** 0.3307 (var=0.0208)
**Predicted under pi_18:** 0.6877 (var=0.0161)
**Predicted under pi_14:** 0.5510 (var=0.0046)

### Experiment 16
**Design**
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[0, 0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Filter for trials where both options have the same number of positive features
    # In the design, these are trials 1-6. In all of these, Option A has a higher 
    # maximum validity (anchor) but exactly the same remaining features as Option B.
    # Therefore, Option B's features are more clustered (lower variance).
    is_matched = data['option_a_ratings'].apply(sum) == data['option_b_ratings'].apply(sum)
    matched_data = data[is_matched]
    if len(matched_data) == 0:
        return 0.0
    # Return the proportion of times Option B was chosen
    return float(matched_data['response'].mean())
```

**Observed (real) value:** 0.8456 (var=0.0113)
**Predicted under pi_18:** 0.1697 (var=0.0079)
**Predicted under pi_14:** 0.1606 (var=0.0128)

### Experiment 17
**Design**
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_target_trial(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        if a == (0, 1, 0, 0, 1) and b == (1, 0, 1, 1, 1):
            return 1
        if a == (0, 1, 1, 0, 1) and b == (0, 1, 0, 0, 1):
            return 3
        return 0
    
    trial_types = data.apply(is_target_trial, axis=1)
    
    t1_mask = (trial_types == 1)
    t3_mask = (trial_types == 3)
    
    p_b_t1 = data[t1_mask]['response'].mean() if t1_mask.sum() > 0 else 0.5
    p_a_t3 = 1.0 - (data[t3_mask]['response'].mean() if t3_mask.sum() > 0 else 0.5)
    
    return float((p_b_t1 + p_a_t3) / 2.0)
```

**Observed (real) value:** 0.2095 (var=0.0222)
**Predicted under pi_18:** 0.4163 (var=0.1014)
**Predicted under pi_14:** 0.2295 (var=0.0326)

### Experiment 18
**Design**
  A=[1, 0, 1, 1, 1, 1, 0, 1]  B=[0, 1, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    mask = (a_str == '10111101') & (b_str == '01000010')
    if mask.sum() == 0:
        return 0.5
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.8400 (var=0.0141)
**Predicted under pi_18:** 0.5708 (var=0.1384)
**Predicted under pi_14:** 0.7908 (var=0.0552)

### Experiment 19
**Design**
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    # Project lists to strings for hashable grouping
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    
    # response=0 means A was chosen, response=1 means B was chosen.
    # So 1 - mean(response) is the empirical probability of choosing A.
    p_A = 1.0 - data.groupby(['A_str', 'B_str'])['response'].mean()
    
    def get_p(a, b):
        if (a, b) in p_A.index:
            return p_A.loc[(a, b)]
        return 0.5
        
    # Trial pairs that differ only by a shared feature added to both options
    # Advocated theory predicts 0 difference; Weakest Link predicts large shifts.
    
    # Trial 2 vs Trial 1 (Shared feature 1 added)
    d1 = get_p('11000', '10110') - get_p('01000', '00110')
    
    # Trial 3 vs Trial 1 (Shared feature 5 added)
    d2 = get_p('01001', '00111') - get_p('01000', '00110')
    
    # Trial 5 vs Trial 4 (Shared feature 1 added)
    d3 = get_p('11100', '10011') - get_p('01100', '00011')
    
    # Trial 8 vs Trial 7 (Shared feature 1 added)
    d4 = get_p('10100', '10010') - get_p('00100', '00010')
    
    return float(np.abs(d1) + np.abs(d2) + np.abs(d3) + np.abs(d4))

```

**Observed (real) value:** 0.0567 (var=0.0378)
**Predicted under pi_18:** 0.0433 (var=0.0339)
**Predicted under pi_14:** 0.0600 (var=0.0527)

### Experiment 20
**Design**
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    is_a_single = data['option_a_ratings'].apply(sum) == 1
    is_b_single = data['option_b_ratings'].apply(sum) == 1
    
    target_trials = is_a_single | is_b_single
    if not target_trials.any():
        return 0.0
        
    df_target = data[target_trials]
    
    chose_multi = ((df_target['option_b_ratings'].apply(sum) == 1) & (df_target['response'] == 0)) | \
                  ((df_target['option_a_ratings'].apply(sum) == 1) & (df_target['response'] == 1))
                  
    return float(chose_multi.mean())

```

**Observed (real) value:** 0.2232 (var=0.0305)
**Predicted under pi_18:** 0.2947 (var=0.0857)
**Predicted under pi_14:** 0.1311 (var=0.0189)

### Experiment 21
**Design**
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Response == 0 means Option A was chosen
    chose_a = (data['response'] == 0).astype(float)
    
    # Identify base trials (last feature is 0 for both options)
    # and derivative trials (last feature is 1 for both options)
    is_derivative = data['option_a_ratings'].apply(lambda x: x[-1] == 1) & data['option_b_ratings'].apply(lambda x: x[-1] == 1)
    is_base = data['option_a_ratings'].apply(lambda x: x[-1] == 0) & data['option_b_ratings'].apply(lambda x: x[-1] == 0)
    
    # Calculate the proportion of choosing Option A in both trial types
    p_a_base = chose_a[is_base].mean()
    p_a_deriv = chose_a[is_derivative].mean()
    
    # The metric is the difference in preference for A
    # Advocated theory: ~0 (shared feature is cancelled)
    # Competing theory: non-zero (shared weak feature increases weakest-link penalty asymmetrically)
    return float(p_a_base - p_a_deriv)
```

**Observed (real) value:** 0.0008 (var=0.0064)
**Predicted under pi_18:** 0.0154 (var=0.0047)
**Predicted under pi_14:** -0.0175 (var=0.0052)

### Experiment 22
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1]  B=[0, 1, 0, 0, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials by their option_a_ratings string representation
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A=[1, 0, 0, 0, 0]
    # Trial 2: A=[1, 0, 0, 0, 1]
    # Trial 5: A=[0, 0, 1, 0, 0]
    # Trial 6: A=[0, 0, 1, 0, 1]
    t1 = data[data['a_str'] == '10000']
    t2 = data[data['a_str'] == '10001']
    t5 = data[data['a_str'] == '00100']
    t6 = data[data['a_str'] == '00101']
    
    # Response is 0 for A, 1 for B, so (1 - mean(response)) is the proportion of A choices
    p_A_t1 = 1.0 - t1['response'].mean() if len(t1) > 0 else 0.5
    p_A_t2 = 1.0 - t2['response'].mean() if len(t2) > 0 else 0.5
    p_A_t5 = 1.0 - t5['response'].mean() if len(t5) > 0 else 0.5
    p_A_t6 = 1.0 - t6['response'].mean() if len(t6) > 0 else 0.5
    
    # Advocated theory predicts P(A) drops from T1 to T2, and P(A) rises from T5 to T6.
    # Competing theory predicts no change in either pair since the shared features cancel out.
    return (p_A_t1 - p_A_t2) + (p_A_t6 - p_A_t5)
```

**Observed (real) value:** 0.0767 (var=0.0438)
**Predicted under pi_18:** -0.0500 (var=0.0547)
**Predicted under pi_14:** 0.0183 (var=0.0434)

### Experiment 23
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    t2_a, t2_b = (1, 0, 0, 1, 1), (0, 0, 1, 1, 0)
    t5_a, t5_b = (0, 1, 0, 1, 1), (0, 0, 1, 0, 1)
    
    b_chosen = []
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == t2_a and b == t2_b:
            b_chosen.append(resp == 1)
        elif a == t2_b and b == t2_a:
            b_chosen.append(resp == 0)
        elif a == t5_a and b == t5_b:
            b_chosen.append(resp == 1)
        elif a == t5_b and b == t5_a:
            b_chosen.append(resp == 0)
            
    if not b_chosen:
        return 0.5
    return sum(b_chosen) / len(b_chosen)
```

**Observed (real) value:** 0.8175 (var=0.0099)
**Predicted under pi_18:** 0.4906 (var=0.0646)
**Predicted under pi_14:** 0.8400 (var=0.0165)

### Experiment 24
**Design**
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    def is_target(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        # Identify trials where A has feature 2, B has features 1 and 3
        # and they share at least one low-validity feature (features 4 or 5)
        return (a[0] == 0 and a[1] == 1 and a[2] == 0 and
                b[0] == 1 and b[1] == 0 and b[2] == 1 and
                sum(a[3:]) > 0)
                
    mask = data.apply(is_target, axis=1)
    if not mask.any():
        return 0.0
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.1744 (var=0.0135)
**Predicted under pi_18:** 0.5810 (var=0.1133)
**Predicted under pi_14:** 0.1892 (var=0.0363)

### Experiment 25
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np

    def is_target_trial(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        return a[4] == 0 and b[4] == 1 and a[:4] == b[:4]

    mask = data.apply(is_target_trial, axis=1)
    target_trials = data[mask]
    
    if len(target_trials) == 0:
        return 0.5
        
    return float(target_trials['response'].mean())
```

**Observed (real) value:** 0.1375 (var=0.0066)
**Predicted under pi_18:** 0.2767 (var=0.0455)
**Predicted under pi_14:** 0.2529 (var=0.0642)

### Experiment 26
**Design**
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Identify trials where B is an empty option and A contains only low-validity features
    mask = (b_str == '00000') & (a_str.isin(['00001', '00010', '00011']))
    
    if mask.sum() == 0:
        return 0.0
        
    # Return the proportion of times the subject chose B (response == 1)
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.8830 (var=0.0105)
**Predicted under pi_18:** 0.6993 (var=0.0811)
**Predicted under pi_14:** 0.7363 (var=0.0482)

### Experiment 27
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    target_trials_a_chosen = 0
    target_trials_total = 0
    
    for _, row in data.iterrows():
        a_ratings = row['option_a_ratings']
        b_ratings = row['option_b_ratings']
        
        unique_a = [i for i, (a, b) in enumerate(zip(a_ratings, b_ratings)) if a == 1 and b == 0]
        unique_b = [i for i, (a, b) in enumerate(zip(a_ratings, b_ratings)) if b == 1 and a == 0]
        
        if len(unique_a) == 1:
            if len(unique_b) == 0 or unique_a[0] < min(unique_b):
                target_trials_total += 1
                if row['response'] == 0:
                    target_trials_a_chosen += 1
                    
    if target_trials_total == 0:
        return 0.5
    return target_trials_a_chosen / target_trials_total
```

**Observed (real) value:** 0.6378 (var=0.0198)
**Predicted under pi_18:** 0.6997 (var=0.0207)
**Predicted under pi_14:** 0.7378 (var=0.0098)

### Experiment 28
**Design**
  A=[0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    mask = ((data['A_str'] == '00000') & (data['B_str'] == '00001')) | \
           ((data['A_str'] == '10000') & (data['B_str'] == '10001'))
    
    if mask.sum() == 0:
        return 0.0
    
    return float((data.loc[mask, 'response'] == 0).mean())

```

**Observed (real) value:** 0.8733 (var=0.0127)
**Predicted under pi_18:** 0.7117 (var=0.0729)
**Predicted under pi_14:** 0.6850 (var=0.0631)

### Experiment 29
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_keys = data['option_a_ratings'].apply(tuple)
    b_keys = data['option_b_ratings'].apply(tuple)
    
    # Trial 4: A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0]
    mask_4 = (a_keys == (0, 1, 1, 0, 0, 0)) & (b_keys == (1, 0, 0, 0, 1, 0))
    # Trial 5: A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0, 0]
    mask_5 = (a_keys == (1, 0, 0, 0, 1, 0)) & (b_keys == (0, 1, 1, 0, 0, 0))
    # Trial 8: A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
    mask_8 = (a_keys == (1, 0, 0, 0, 0, 1)) & (b_keys == (0, 1, 1, 0, 0, 0))
    
    choices_high_max = 0
    total = 0
    
    if mask_4.any():
        choices_high_max += (data.loc[mask_4, 'response'] == 1).sum()
        total += mask_4.sum()
        
    if mask_5.any():
        choices_high_max += (data.loc[mask_5, 'response'] == 0).sum()
        total += mask_5.sum()
        
    if mask_8.any():
        choices_high_max += (data.loc[mask_8, 'response'] == 0).sum()
        total += mask_8.sum()
        
    if total == 0:
        return 0.5
        
    return float(choices_high_max / total)
```

**Observed (real) value:** 0.3052 (var=0.0260)
**Predicted under pi_18:** 0.3237 (var=0.0482)
**Predicted under pi_14:** 0.1356 (var=0.0139)

### Experiment 30
**Design**
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option A has a large spread of validities (features 1 and 5)
    mask = data['option_a_ratings'].apply(lambda x: list(x) == [1, 0, 0, 0, 1])
    if mask.sum() == 0:
        return 0.0
    return float(data[mask]['response'].mean())
```

**Observed (real) value:** 0.8579 (var=0.0059)
**Predicted under pi_18:** 0.4005 (var=0.0460)
**Predicted under pi_14:** 0.8568 (var=0.0117)

### Experiment 31
**Design**
  A=[1, 0, 0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Identify Trial 1 where Option A and Option B have the exact same range of validities
    # but different standard deviations.
    # Trial 1: A=[1, 0, 0, 1, 1, 1, 0, 0], B=[0, 1, 1, 0, 0, 0, 1, 1]
    is_trial_1 = data['option_a_ratings'].apply(tuple) == (1, 0, 0, 1, 1, 1, 0, 0)
    
    # Calculate the proportion of times Option A was chosen in Trial 1
    trial_1_data = data[is_trial_1]
    if len(trial_1_data) == 0:
        return 0.5
        
    return float((trial_1_data['response'] == 0).mean())
```

**Observed (real) value:** 0.1675 (var=0.0112)
**Predicted under pi_18:** 0.2250 (var=0.0397)
**Predicted under pi_14:** 0.2125 (var=0.0431)

### Experiment 32
**Design**
  A=[1, 0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_keys = data['option_a_ratings'].apply(tuple)
    b_keys = data['option_b_ratings'].apply(tuple)
    
    t2_a = (1, 0, 0, 0, 0, 1, 1, 0, 0, 1, 0, 0)
    t2_b = (0, 0, 0, 1, 1, 0, 0, 1, 1, 0, 0, 0)
    
    t4_a = (1, 1, 0, 0, 0, 1, 1, 0, 0, 1, 1, 0)
    t4_b = (0, 1, 0, 1, 1, 0, 0, 1, 1, 0, 1, 0)
    
    mask = ((a_keys == t2_a) & (b_keys == t2_b)) | ((a_keys == t4_a) & (b_keys == t4_b))
    return float(data[mask]['response'].mean())
```

**Observed (real) value:** 0.8526 (var=0.0133)
**Predicted under pi_18:** 0.5689 (var=0.0109)
**Predicted under pi_14:** 0.8189 (var=0.0197)

### Experiment 33
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify Trial 5 where A=[0, 1, 0, 0, 1] and B=[0, 0, 1, 1, 0]
    a_seq = data['option_a_ratings'].apply(tuple)
    t5_mask = (a_seq == (0, 1, 0, 0, 1))
    
    # Response is 1 if B is chosen, 0 if A is chosen.
    # We return the proportion of times B is chosen in this trial.
    return float(data.loc[t5_mask, 'response'].mean())
```

**Observed (real) value:** 0.8500 (var=0.0094)
**Predicted under pi_18:** 0.2787 (var=0.0578)
**Predicted under pi_14:** 0.8250 (var=0.0273)

### Experiment 34
**Design**
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Convert option A ratings to string to uniquely identify trial types
    a_str = data['option_a_ratings'].apply(lambda x: "".join(str(int(v)) for v in x))
    chose_A = (data['response'] == 0).astype(float)
    df = pd.DataFrame({'A_str': a_str, 'chose_A': chose_A})
    
    # Get mean P(Choose A) for each trial type
    p_A = df.groupby('A_str')['chose_A'].mean().to_dict()
    
    # Trials where Advocated Theory predicts high P(A) (no spread penalty for A, high for B)
    # and Competing Theory predicts low P(A) (A has fewer features, B's sum of features dominates)
    p_T5 = p_A.get("10000", 0.5)
    p_T6 = p_A.get("10001", 0.5)
    
    # Trials where Advocated Theory predicts low P(A) (high spread penalty for A, low for B)
    # and Competing Theory predicts high P(A) (A's top feature is stronger, dominating due to diminishing marginal utility)
    p_T1 = p_A.get("01001", 0.5)
    p_T2 = p_A.get("11001", 0.5)
    p_T3 = p_A.get("10010", 0.5)
    p_T4 = p_A.get("10011", 0.5)
    
    # Contrast the two sets of trials
    high_adv = (p_T5 + p_T6) / 2.0
    low_adv = (p_T1 + p_T2 + p_T3 + p_T4) / 4.0
    
    return float(high_adv - low_adv)
```

**Observed (real) value:** 0.7100 (var=0.0395)
**Predicted under pi_18:** -0.0242 (var=0.0518)
**Predicted under pi_14:** 0.7025 (var=0.0632)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the majority of experiments (e.g., Exp 2, 14, 18, 23, 30, 32, 33, 34), THEORY 2 (pi_14, Thresholded Unique Features with Spread Penalty) significantly outperforms THEORY 1 (pi_18, Sequential Unique Feature Comparison). THEORY 2 correctly captures the strong penalties applied to options with a wide variance in their unique features, aligning closely with observed choice proportions. THEORY 1, relying on sequential evaluation and early stopping, consistently overestimates the preference for options with a single high-validity feature paired with low-validity features. However, both theories fail dramatically on Experiment 16, where subjects overwhelmingly preferred Option B (lower variance, slightly lower max validity) over Option A. This suggests that while THEORY 2's spread penalty is on the right track, it misses a crucial aspect of how feature clustering or coherence is evaluated.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a brand-new theory to replace THEORY 1. The new theory should build on the conceptual successes of THEORY 2 (which correctly identifies that subjects penalize variance/spread in unique features) but introduce a mechanism for 'Feature Coherence' or 'Density'. For instance, decision-makers might evaluate the density or clustering of active features, strongly preferring options where positive features are contiguous or similar in validity (low variance), and heavily discounting isolated high-validity features if they are disconnected from the rest of the option's profile. This would explain both the general spread-penalty effects seen across the benchmark and the specific preference for clustered features observed in Experiment 16."
}
```

## Usage

```json
{
  "prompt_token_count": 25312,
  "candidates_token_count": 376,
  "total_token_count": 26918
}
```
