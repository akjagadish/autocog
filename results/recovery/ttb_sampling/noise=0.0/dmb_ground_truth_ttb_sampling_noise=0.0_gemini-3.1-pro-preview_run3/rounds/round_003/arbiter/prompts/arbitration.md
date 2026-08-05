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
Take-The-Best (TTB) heuristic: People make decisions by considering features one at a time, ordered by their validity. They stop at the first feature that discriminates between the options and choose the option with the higher value on that feature. If no features discriminate, they guess. This is a non-compensatory, lexicographic process.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    epsilon = float(parameters["epsilon"])
    
    # Sort features by validity descending
    order = np.argsort(validities)[::-1]
    
    p_core = np.array([0.5, 0.5])
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return np.random.choice(len(probs), p=probs)

## THEORY 2 — pi_4
Probabilistic Take-The-Best (PTTB) with exponential weighting: Decision-makers search through features sequentially but stochastically. The probability of checking a feature is proportional to an exponential function of its validity (exp(gamma * validity)), allowing high-validity features to strongly dominate the search order. The search stops at the first feature that discriminates between the options, and the option favored by that feature is chosen. If no features discriminate, the decision-maker guesses. This yields a Luce choice rule over the exponentially weighted discriminating features.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("PTTB expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    
    validities = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    epsilon = float(parameters["epsilon"])
    
    # Identify discriminating features for each option
    d_a = (a > b).astype(float)
    d_b = (b > a).astype(float)
    d_any = d_a + d_b
    
    if np.sum(d_any) == 0:
        p_a = 0.5
    else:
        # To prevent numerical overflow, subtract max validity among discriminating features
        max_v = np.max(validities[d_any > 0])
        weights = np.exp(gamma * (validities - max_v))
        
        # Sum of weights of features favoring A and B
        w_a = np.sum(d_a * weights)
        w_b = np.sum(d_b * weights)
        
        # The probability that the first discriminating feature found favors A
        p_a = w_a / (w_a + w_b)
        
    p_core = np.array([p_a, 1.0 - p_a])
    
    # Incorporate uniform lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return np.random.choice(len(probs), p=probs)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.85, 0.82, 0.79, 0.76, 0.73]

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 8: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 9: A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  trial 10: A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 11: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 12: A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]

**Rationale:** To strongly dissociate Take-The-Best (TTB) from Probabilistic Take-The-Best (PTTB), we exploit their differing sensitivity to multiple lower-validity discriminating features. TTB deterministically selects the option favored by the single highest-validity discriminating feature, completely ignoring all other features. PTTB, however, stochastically samples from all discriminating features with probabilities proportional to an exponential function of their validities. By creating critical trials where Option A is favored by the single most valid discriminating feature, but Option B is favored by several slightly less valid features, TTB strongly predicts Option A. In contrast, PTTB's choice probabilities will be much more graded and can even favor Option B if the sum of the exponential weights of B's features exceeds A's (for low to moderate gamma values). We closely space the validities to maximize PTTB's sensitivity to lower-validity features, ensuring a stark quantitative dissociation from TTB's deterministic, single-feature focus.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
Through mathematical analysis of the parameter spaces, we find that for the vast majority of subjects (~95%), Probabilistic Take-The-Best (PTTB) will perfectly mimic the deterministic choices of Take-The-Best (TTB) because the exponential weighting function (gamma parameter up to 200) heavily polarizes the choice probabilities. Consequently, looking for trial-by-trial deviations fails because they only exist for a tiny fraction of low-gamma PTTB subjects, who end up inflating the variance without moving the mean sufficiently. 

The true, robust mathematical difference between the models lies in their uniform lapse rates: TTB's epsilon ranges up to 0.50 (expected adherence 87.5%), while PTTB's epsilon only ranges up to 0.25 (expected adherence 93.75%). By computing the subject's overall adherence to TTB and applying a hard threshold at 85%, we create a highly discriminatory binary metric. Approximately 40-50% of TTB subjects will fail to reach this 85% adherence threshold due to their higher lapse rates. In stark contrast, over 90% of PTTB subjects will comfortably clear it. This binarization perfectly exploits the difference in the noise parameter bounds, ensuring a massive mean difference between the theories while strictly bounding the between-subject variance.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # TTB strictly predicts Option A for Trials 1-10, and Option B for Trials 11-12.
    # We define adherence to TTB as choosing the option TTB predicts.
    ttb_preds = {
        '1000001111': 0, # T1: A
        '1100010111': 0, # T2: A
        '0100000111': 0, # T3: A
        '0110001011': 0, # T4: A
        '0010000011': 0, # T5: A
        '1010001011': 0, # T6: A
        '1001001101': 0, # T7: A
        '1110000011': 0, # T8: A
        '1011001001': 0, # T9: A
        '0111000001': 0, # T10: A
        '0011111000': 1, # T11: B
        '0110110010': 1  # T12: B
    }
    
    data['trial_id'] = data.apply(
        lambda row: ''.join([str(int(v)) for v in row['option_a_ratings']]) + 
                    ''.join([str(int(v)) for v in row['option_b_ratings']]), 
        axis=1
    )
    
    data['ttb_match'] = (data['response'] == data['trial_id'].map(ttb_preds)).astype(float)
    
    # Calculate overall TTB adherence for the subject across all 96 trials
    overall_adherence = data['ttb_match'].mean()
    
    # Return 1.0 if adherence is above 85%, else 0.0. 
    # This heavily penalizes the high uniform lapse rate of TTB (epsilon up to 0.5),
    # while capturing the fact that >95% of PTTB subjects (who typically have high gamma 
    # and epsilon <= 0.25) will easily clear this threshold.
    return 1.0 if overall_adherence > 0.85 else 0.0


### RESULTS
- Predicted under pi_3 (simulated): 1.0000 (var=0.1924)
- Predicted under pi_4 (simulated): 0.0000 (var=0.2304)
- Observed on real data: 1.0000 (var=0.2400)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.9, 0.88, 0.86, 0.84, 0.82]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 7: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 9: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 10: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Rationale:** To strongly dissociate Probabilistic Take-The-Best (PTTB) from deterministic Take-The-Best (TTB), we use a 5-feature design with closely spaced validities. TTB strictly chooses the option favored by the single most valid discriminating feature, completely ignoring all other features. In contrast, PTTB stochastically selects a discriminating feature with a probability proportional to an exponential function of its validity. By pitting the single best feature against a coalition of several slightly less valid features, TTB predicts a deterministic choice for the option with the best feature, while PTTB's choice probabilities will be much more graded and can even favor the opposing option (for low to moderate gamma values) because the sum of the exponential weights of the opposing features exceeds that of the single best feature.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
Under the deterministic Take-The-Best (TTB) model, the probability of making a TTB-consistent choice is constant across all trial types (1 - epsilon/2). Thus, the difference in TTB match rates between trials where the TTB choice is supported by 3 features and trials where it is supported by only 1 feature should be exactly 0 on average. Under Probabilistic Take-The-Best (PTTB), features are sampled stochastically proportional to their exponential validities. When the TTB choice is supported by only 1 feature, the opposing coalition has 3 or 4 features, presenting a much larger combined probability mass to be sampled first compared to trials where the TTB choice is supported by 3 features. Therefore, PTTB predicts a significantly higher TTB match rate when 3 features favor the TTB choice than when only 1 feature does, yielding a strongly positive difference.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    A = np.vstack(data['option_a_ratings'].values)
    B = np.vstack(data['option_b_ratings'].values)
    
    # TTB decides based on the first feature where A and B differ
    diff = A != B
    first_diff_idx = np.argmax(diff, axis=1)
    
    row_indices = np.arange(len(data))
    a_vals = A[row_indices, first_diff_idx]
    b_vals = B[row_indices, first_diff_idx]
    
    # TTB choice: 0 for A, 1 for B
    ttb_choices = (b_vals > a_vals).astype(int)
    
    # Match between subject response and TTB choice
    responses = data['response'].values
    ttb_match = (responses == ttb_choices).astype(float)
    
    # Count how many features favor the TTB choice
    d_a = (A > B).astype(int)
    d_b = (B > A).astype(int)
    
    ttb_features_count = np.where(ttb_choices == 0, d_a.sum(axis=1), d_b.sum(axis=1))
    
    # Compare trials where TTB is supported by 3 features vs 1 feature
    mask_3 = (ttb_features_count == 3)
    mask_1 = (ttb_features_count == 1)
    
    if np.sum(mask_3) == 0 or np.sum(mask_1) == 0:
        return 0.0
        
    return float(np.mean(ttb_match[mask_3]) - np.mean(ttb_match[mask_1]))

### RESULTS
- Predicted under pi_3 (simulated): 0.0017 (var=0.0075)
- Predicted under pi_4 (simulated): 0.0928 (var=0.0136)
- Observed on real data: -0.0033 (var=0.0076)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.9, 0.85, 0.6, 0.55, 0.5])
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    a_wadd = np.sum(a_ratings * validities, axis=1)
    b_wadd = np.sum(b_ratings * validities, axis=1)
    
    conflict_mask = (a_wins > b_wins) & (b_wadd > a_wadd)
    
    if np.sum(conflict_mask) == 0:
        return 0.5
        
    return float(np.mean(data['response'].values[conflict_mask]))
```

**Observed (real) value:** 0.8844 (var=0.0081)
**Predicted under pi_3:** 0.8728 (var=0.0081)
**Predicted under pi_4:** 0.9078 (var=0.0114)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    is_a_heavy = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))
    is_b_heavy = data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))
    
    is_a_many = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
    is_b_many = data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
    
    trial_1 = is_a_heavy & is_b_many
    trial_2 = is_a_many & is_b_heavy
    
    critical_trials = trial_1 | trial_2
    
    if not critical_trials.any():
        return 0.5
        
    heavy_chosen = (trial_1 & (data['response'] == 0)) | (trial_2 & (data['response'] == 1))
    
    return float(heavy_chosen[critical_trials].mean())
```

**Observed (real) value:** 0.8533 (var=0.0160)
**Predicted under pi_3:** 0.8750 (var=0.0083)
**Predicted under pi_4:** 0.9083 (var=0.0120)

### Experiment 5
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    v = np.array([0.95, 0.9, 0.6, 0.55, 0.5])
    a_v = np.sum(a_ratings * v, axis=1)
    b_v = np.sum(b_ratings * v, axis=1)
    
    tally_prefers_a = a_wins > b_wins
    tally_prefers_b = b_wins > a_wins
    
    wadd_prefers_a = a_v > b_v
    wadd_prefers_b = b_v > a_v
    
    conflict_a = tally_prefers_a & wadd_prefers_b
    conflict_b = tally_prefers_b & wadd_prefers_a
    
    conflict_mask = conflict_a | conflict_b
    
    if not np.any(conflict_mask):
        return 0.5
        
    responses = data['response'].values
    
    tally_aligned = np.zeros(len(data), dtype=bool)
    tally_aligned[conflict_a & (responses == 0)] = True
    tally_aligned[conflict_b & (responses == 1)] = True
    
    return float(np.mean(tally_aligned[conflict_mask]))
```

**Observed (real) value:** 0.1500 (var=0.0150)
**Predicted under pi_3:** 0.1625 (var=0.0258)
**Predicted under pi_4:** 0.0825 (var=0.0110)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def f0_chosen(row):
        a0 = row['option_a_ratings'][0]
        b0 = row['option_b_ratings'][0]
        if a0 == b0:
            return None
        return a0 if row['response'] == 0 else b0
        
    f0_vals = data.apply(f0_chosen, axis=1).dropna()
    if len(f0_vals) == 0:
        return 0.5
    return float(f0_vals.mean())
```

**Observed (real) value:** 0.9033 (var=0.0065)
**Predicted under pi_3:** 0.8964 (var=0.0042)
**Predicted under pi_4:** 0.9011 (var=0.0120)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        pred = None
        for i in range(len(a)):
            if a[i] > b[i]:
                pred = 0
                break
            elif b[i] > a[i]:
                pred = 1
                break
        if pred is not None:
            matches.append(1 if r == pred else 0)
            
    return float(np.mean(matches)) if len(matches) > 0 else 0.5
```

**Observed (real) value:** 0.8671 (var=0.0115)
**Predicted under pi_3:** 0.8735 (var=0.0058)
**Predicted under pi_4:** 0.9087 (var=0.0050)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    # TTB winner: based on the first feature that discriminates
    diff = a_ratings - b_ratings
    first_diff_idx = np.argmax(diff != 0, axis=1)
    ttb_winner = np.where(diff[np.arange(len(diff)), first_diff_idx] > 0, 0, 1)
    has_diff = np.any(diff != 0, axis=1)
    
    # Tally winner: based on simple sum of features
    sum_a = np.sum(a_ratings, axis=1)
    sum_b = np.sum(b_ratings, axis=1)
    tally_winner = np.where(sum_a > sum_b, 0, np.where(sum_b > sum_a, 1, -1))
    
    # Identify conflict trials where TTB and Tallying disagree
    conflict = has_diff & (tally_winner != -1) & (ttb_winner != tally_winner)
    
    if not np.any(conflict):
        return 0.0
        
    responses = data['response'].values
    tally_chosen = (responses[conflict] == tally_winner[conflict]).sum()
    
    return float(tally_chosen / np.sum(conflict))
```

**Observed (real) value:** 0.1378 (var=0.0101)
**Predicted under pi_3:** 0.1311 (var=0.0080)
**Predicted under pi_4:** 0.1142 (var=0.0167)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (Take-The-Best, pi_3) consistently and remarkably outperforms Theory 2 (Probabilistic Take-The-Best, pi_4). In Experiment 1, pi_3 perfectly predicts the binarized adherence metric (1.0 vs 0.0 for pi_4, observed 1.0). In Experiment 2, pi_3 predicts the observed ~0.0 difference between 3-feature and 1-feature support trials, while pi_4 incorrectly predicts a positive difference. Furthermore, across Experiments 3-8, pi_3 matches the observed values more closely than pi_4, confirming that the deterministic, non-compensatory lexicographic stopping rule of standard TTB is a much better description of human behavior in this paradigm than a stochastic exponential sampling rule.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Theory 2 (PTTB) is degenerate and fails to capture the deterministic nature of feature-based choices observed in the data. Propose a brand-new theory, such as a 'Mixture of TTB and Tallying' or 'Take-Two' model. For instance, a mixture model would posit that while the majority of decision-making is driven by the pure deterministic TTB heuristic, a subset of trials or subjects rely on a compensatory Tallying strategy (simply counting the number of positive features for each option). This would maintain the strong non-compensatory baseline of TTB while providing a more realistic structural alternative to pure uniform lapses (epsilon) for the remaining variance."
}
```

## Usage

```json
{
  "prompt_token_count": 9277,
  "candidates_token_count": 350,
  "total_token_count": 10558
}
```
