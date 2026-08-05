# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_5") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_5" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
People compare two options by consulting cues one at a time in order of validity, stopping at the first cue that discriminates between the two options. That cue alone determines the choice: the option with the higher value on the discriminating cue wins, and no other cue is consulted. Cues with lower validity are never reached when a higher-validity cue already discriminates, so Take The Best is a "one-reason" decision rule — only a single feature is ever used on any given choice. Because only the sign of the comparison on the top discriminating cue matters, TTB ignores both the magnitude of that difference and all information on lower-validity cues, making it maximally frugal in the use of evidence. Cue validities are subjective and can be learned, inferred from instructions, or fixed by task structure. When no cue discriminates (all feature-wise comparisons tie) the learner has no basis for preference and must guess. Response noise enters through a softmax over the binary TTB score (winner = 1, loser = 0) with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Take The Best (Gigerenzer & Goldstein 1996).
    # Stimulus is the pair of option feature vectors for the current
    # trial: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B. Cue cascade: features are consulted in order
    # of descending validity; the first discriminating cue (strict
    # inequality) determines the winner; if no cue discriminates,
    # the model guesses uniformly. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )
    # Descending validity; argsort is stable so validity ties break
    # toward the earlier feature index.
    cue_order = np.argsort(-val, kind="stable").tolist()

    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        if b[j] > a[j]:
            winner = 1
            break

    if winner is None:
        # No discriminating cue — pure guess.
        return np.ones(2) / 2.0

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the
    # binary TTB score this collapses to sigmoid(beta) for the winner,
    # giving a direct mapping from beta onto the paper's flip-noise
    # levels (beta=0 ↔ 50/50; beta ≫ 1 ↔ deterministic).
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_5
Final parameter update: theta=[0.0, 2.5], beta=[0.1, 20.0], epsilon=[0.0, 0.2]. Initial logic and parameters are validated. The model executes sequential evidence accumulation over log-odds, directly halting early to enforce the strong lexicographic baseline observed in human data.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Convert validities to log-odds
    val = np.clip(val, 0.001, 0.999)
    log_odds = np.log(val / (1.0 - val))
    
    theta = float(parameters["theta"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Process cues in descending order of validity
    cue_order = np.argsort(-val, kind="stable").tolist()
    
    E = 0.0
    for j in cue_order:
        E += log_odds[j] * (a[j] - b[j])
        # Stop search if evidence threshold is reached
        if abs(E) >= theta:
            break
            
    # Convert accumulated evidence to probability using softmax/logistic
    z = beta * E
    z = np.clip(z, -100, 100) # Prevent overflow
    p_a = 1.0 / (1.0 + np.exp(-z))
    
    p_core = np.array([p_a, 1.0 - p_a])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)

## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=5):** [0.75, 0.7, 0.65, 0.6, 0.55]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 3: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 4: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 5: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 7: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 8: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 9: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 10: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate Take The Best (TTB) from the Sequential Evidence Accumulation over log-odds model, we use a 5-feature design with moderately high, descending validities. TTB employs a strict lexicographic stopping rule, halting at the very first discriminating cue regardless of the remaining evidence. The competing model, however, accumulates the log-odds of the validities and only stops when a threshold (theta) is reached. Because the top validity is set to 0.75 (log-odds ~ 1.1), it is not high enough to reliably exceed the competing model's upper threshold limits (up to 2.5) on its own. By pitting the highest-validity discriminating cue against all subsequent lower-validity cues, TTB will deterministically choose the option favored by the single best cue, whereas the evidence accumulation model will integrate the opposing cues and ultimately favor the other option.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
Calculates the proportion of trials where the subject chooses the option with strictly fewer positive features, out of all trials where the feature counts differ. TTB will frequently choose the option with fewer features if it possesses the single most valid cue, whereas the evidence accumulator integrates all cues and thus heavily favors the option with the greater number of positive features.

Source:
def metric(data: pd.DataFrame) -> float:
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    diff_mask = sum_a != sum_b
    if not diff_mask.any():
        return 0.5
    filtered_data = data[diff_mask]
    sum_a_diff = sum_a[diff_mask]
    sum_b_diff = sum_b[diff_mask]
    chose_fewer = ((filtered_data['response'] == 0) & (sum_a_diff < sum_b_diff)) | ((filtered_data['response'] == 1) & (sum_b_diff < sum_a_diff))
    return float(chose_fewer.mean())

### RESULTS
- Predicted under pi_1 (simulated): 0.7564 (var=0.0053)
- Predicted under pi_5 (simulated): 0.3614 (var=0.0592)
- Observed on real data: 0.7494 (var=0.0080)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.85, 0.8, 0.75, 0.7, 0.65]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Rationale:** To quantitatively dissociate Sequential Evidence Accumulation over log-odds from Take The Best (TTB), we use a 5-feature design with a descending set of validities. TTB employs a strict lexicographic stopping rule, choosing the option favored by the single highest-validity discriminating cue and ignoring all subsequent cues. In contrast, the Sequential Evidence Accumulation model accumulates the log-odds of the validities and halts only when a threshold (theta) is reached. By setting the top validity to 0.85 (log-odds ~ 1.73), it is not high enough to reliably exceed the accumulation model's upper threshold limits (up to 2.5) on its own. By pitting the highest-validity discriminating cue against multiple subsequent lower-validity cues, TTB will deterministically choose the option favored by the single best cue, whereas the evidence accumulation model (for higher theta values) will integrate the opposing cues and ultimately favor the other option.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
In all trials, the single highest-validity discriminating cue favors Option A, meaning Take The Best (TTB) will consistently choose Option A across the entire experiment. Thus, for TTB, any Option B choices are purely due to epsilon lapse noise, which applies uniformly across all trials. By taking the within-subject difference in the proportion of B choices between trials where the full evidence heavily favors B (Trials 1 and 3) and trials where the full evidence still favors A (Trials 4, 5, 6), we subtract out this baseline noise. TTB will yield a difference of exactly 0 with extremely low variance. In contrast, the Sequential Evidence Accumulation model will yield a positive difference, as subjects with higher thresholds will reliably choose B in the first set but A in the second.

Source:
def metric(data: pd.DataFrame) -> float:
    a_tuples = data['option_a_ratings'].apply(tuple)
    b_tuples = data['option_b_ratings'].apply(tuple)
    
    # Trials where Evidence Accumulation (high theta) favors B
    t1 = (a_tuples == (1, 0, 0, 0, 0)) & (b_tuples == (0, 1, 1, 1, 1))
    t3 = (a_tuples == (0, 1, 0, 0, 0)) & (b_tuples == (0, 0, 1, 1, 1))
    mask_favor_b = t1 | t3
    
    # Trials where Evidence Accumulation (high theta) favors A
    t4 = (a_tuples == (1, 1, 0, 0, 0)) & (b_tuples == (0, 0, 1, 1, 1))
    t5 = (a_tuples == (0, 1, 1, 0, 0)) & (b_tuples == (0, 0, 0, 1, 1))
    t6 = (a_tuples == (1, 0, 0, 1, 1)) & (b_tuples == (0, 1, 1, 0, 0))
    mask_favor_a = t4 | t5 | t6
    
    if not mask_favor_b.any() or not mask_favor_a.any():
        return 0.0
        
    p_b_when_b_favored = float(data.loc[mask_favor_b, 'response'].mean())
    p_b_when_a_favored = float(data.loc[mask_favor_a, 'response'].mean())
    
    return p_b_when_b_favored - p_b_when_a_favored

### RESULTS
- Predicted under pi_1 (simulated): 0.0048 (var=0.0062)
- Predicted under pi_5 (simulated): 0.2721 (var=0.1319)
- Observed on real data: 0.0042 (var=0.0061)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    agreements = 0
    total = 0
    for a, b, resp in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        ttb_winner = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_winner = 0
                break
            elif b[i] > a[i]:
                ttb_winner = 1
                break
        
        if ttb_winner is not None:
            if resp == ttb_winner:
                agreements += 1
            total += 1
            
    return float(agreements / total) if total > 0 else 0.0
```

**Observed (real) value:** 0.8492 (var=0.0099)
**Predicted under pi_1:** 0.8342 (var=0.0101)
**Predicted under pi_5:** 0.8940 (var=0.0098)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
import pandas as pd
import numpy as np

def metric(data: pd.DataFrame) -> float:
    matches = 0
    total = 0
    for a, b, resp in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        a_wins = sum(1 for x, y in zip(a, b) if x > y)
        b_wins = sum(1 for x, y in zip(a, b) if y > x)
        if a_wins > b_wins:
            matches += (resp == 0)
            total += 1
        elif b_wins > a_wins:
            matches += (resp == 1)
            total += 1
    return float(matches / total) if total > 0 else 0.5

```

**Observed (real) value:** 0.1739 (var=0.0108)
**Predicted under pi_1:** 0.1358 (var=0.0099)
**Predicted under pi_5:** 0.1061 (var=0.0124)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    resp = data['response'].values
    
    diff = a_ratings - b_ratings
    is_diff = diff != 0
    has_diff = is_diff.any(axis=1)
    
    first_diff_idx = is_diff.argmax(axis=1)
    first_diff_val = diff[np.arange(len(diff)), first_diff_idx]
    
    ttb_pred = np.where(first_diff_val > 0, 0, 1)
    
    match = (resp[has_diff] == ttb_pred[has_diff])
    return float(match.mean()) if len(match) > 0 else 0.5
```

**Observed (real) value:** 0.8400 (var=0.0088)
**Predicted under pi_1:** 0.8827 (var=0.0091)
**Predicted under pi_5:** 0.7312 (var=0.0981)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # TTB always chooses Option A (response = 0) across all 8 trials in this design
    # because A always has the single best discriminating cue. 
    # WADD, by contrast, integrates all cues and will frequently choose Option B 
    # (response = 1) because the sum of lower-validity cues often outweighs the single best cue.
    return float(data['response'].mean())
```

**Observed (real) value:** 0.1613 (var=0.0125)
**Predicted under pi_1:** 0.1537 (var=0.0066)
**Predicted under pi_5:** 0.2425 (var=0.0665)

### Experiment 7
**Design**
  A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    corrs = []
    # Calculate the correlation between opposing cues and choice for each subject
    for subj, subj_data in data.groupby('subject_id'):
        a_matrix = np.vstack(subj_data['option_a_ratings'].values)
        b_matrix = np.vstack(subj_data['option_b_ratings'].values)
        
        # Count how many cues strictly favor Option B over Option A
        favor_b = np.sum(b_matrix > a_matrix, axis=1)
        resp = subj_data['response'].values
        
        # Only compute correlation if there is variance in the responses
        if np.std(favor_b) > 1e-5 and np.std(resp) > 1e-5:
            r = np.corrcoef(favor_b, resp)[0, 1]
            corrs.append(r)
        else:
            corrs.append(0.0)
            
    if len(corrs) == 0:
        return 0.0
        
    # For a single subject's slice, this returns their individual correlation.
    # For the pooled dataframe, this returns the 90th percentile across all subjects,
    # specifically isolating the heavy right tail of Probabilistic TTB subjects.
    return float(np.percentile(corrs, 90))
```

**Observed (real) value:** 0.2175 (var=0.0136)
**Predicted under pi_1:** 0.0845 (var=0.0071)
**Predicted under pi_5:** 0.4710 (var=0.0429)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Low opposing cues (1 cue): Trials 1, 5, 7
    low_mask = (
        ((data['A_str'] == '100000') & (data['B_str'] == '010000')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001000')) |
        ((data['A_str'] == '000001') & (data['B_str'] == '100000'))
    )
    
    # High opposing cues (>= 3 cues): Trials 3, 4, 6
    high_mask = (
        ((data['A_str'] == '100000') & (data['B_str'] == '011100')) |
        ((data['A_str'] == '100000') & (data['B_str'] == '011111')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001111'))
    )
    
    # Determine if the choice was consistent with the TTB winner
    data['ttb_correct'] = 0
    
    # TTB Winner is A for Trials 1, 3, 4, 5, 6
    a_winners = (
        ((data['A_str'] == '100000') & (data['B_str'] == '010000')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001000')) |
        ((data['A_str'] == '100000') & (data['B_str'] == '011100')) |
        ((data['A_str'] == '100000') & (data['B_str'] == '011111')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001111'))
    )
    data.loc[a_winners & (data['response'] == 0), 'ttb_correct'] = 1
    
    # TTB Winner is B for Trial 7
    b_winners = (
        ((data['A_str'] == '000001') & (data['B_str'] == '100000'))
    )
    data.loc[b_winners & (data['response'] == 1), 'ttb_correct'] = 1
    
    p_low = data.loc[low_mask, 'ttb_correct'].mean()
    p_high = data.loc[high_mask, 'ttb_correct'].mean()
    
    if pd.isna(p_low): p_low = 0.0
    if pd.isna(p_high): p_high = 0.0
    
    return float(p_low - p_high)
```

**Observed (real) value:** -0.0178 (var=0.0076)
**Predicted under pi_1:** 0.0061 (var=0.0092)
**Predicted under pi_5:** 0.0289 (var=0.0093)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (Take The Best) significantly outperforms Theory 2 (Sequential Evidence Accumulation). In Experiments 1, 2, 3, 5, and 6, the observed data strongly aligns with the strict lexicographic stopping rule of TTB, and Theory 2 fails to capture this because it integrates too much evidence. However, Experiment 7 reveals a subtle but real correlation (0.2175) between opposing lower-validity cues and choice, which pure TTB underpredicts (0.0845) and the Evidence Accumulation model overpredicts (0.4710). This suggests that while TTB dominates the population's behavior, there is a secondary mechanism at play\u2014either a subset of subjects using a compensatory strategy, or individuals occasionally switching strategies.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a Strategy Mixture theory. The new theory should posit that the population consists of a mixture of decision-makers: a large majority relies on the strict, non-compensatory Take The Best (TTB) heuristic, while a smaller proportion uses a compensatory strategy (such as Tallying or Weighted Additive). This mixture will preserve the dominant TTB-like predictions that successfully explain Experiments 1-6 and 8, while correctly capturing the right-tail sensitivity to opposing cues observed in Experiment 7."
}
```

## Usage

```json
{
  "prompt_token_count": 8631,
  "candidates_token_count": 313,
  "total_token_count": 9818
}
```
