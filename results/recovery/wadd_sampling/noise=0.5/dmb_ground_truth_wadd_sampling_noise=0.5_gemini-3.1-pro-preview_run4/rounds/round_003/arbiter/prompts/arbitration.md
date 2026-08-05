# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_5" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_5" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_5
Sequential Evidence Accumulation: Decision-makers inspect cues sequentially in order of validity, accumulating evidence for the favored option. The evidence contributed by each cue is its validity scaled by a non-linear parameter gamma. Search terminates when the absolute evidence difference reaches a threshold theta, or when all cues are exhausted. A choice is then made based on the accumulated evidence with softmax noise. This unified mechanism smoothly interpolates between Take-The-Best (low threshold), Tallying (high threshold, gamma=0), and Weighted Additive (high threshold, gamma>0).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    theta = float(parameters["theta"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Scale validities
    v = np.power(val, gamma)
    
    # Order cues by descending validity
    cue_order = np.argsort(-val, kind="stable")
    
    E = 0.0
    for j in cue_order:
        diff = a[j] - b[j]
        if diff != 0:
            E += v[j] * diff
            if abs(E) >= theta:
                break
                
    # E > 0 means A is favored; E < 0 means B is favored
    scores = np.array([E, 0.0])
    
    # Softmax choice
    z = beta * (scores - np.max(scores))
    e_vals = np.exp(z)
    p = e_vals / np.sum(e_vals)
    
    # Add lapse rate
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_4
Strategy Mixture (Take-The-Best and Tallying with Tallying Bias): Decision-makers are heterogeneous in their strategy use, probabilistically switching between strategies. On any given choice, a subject has a probability 'p_ttb' of applying a one-reason lexicographic heuristic (Take-The-Best) and a probability '1 - p_ttb' of applying an equal-weight compensatory heuristic (Tallying). Empirical data suggests that people generally favor Tallying over Take-The-Best in these environments, so the probability of using Take-The-Best is bounded between 10% and 50%, ensuring the mixture slightly favors Tallying to better match observed aggregate choice probabilities.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    
    # Take-The-Best (TTB) Prediction
    cue_order = np.argsort(-val, kind="stable").tolist()
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        p_ttb_core = np.array([0.5, 0.5])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        beta_ttb = float(parameters["beta_ttb"])
        z_ttb = beta_ttb * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb_core = e_ttb / np.sum(e_ttb)
        
    # Tallying Prediction
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores_tally = np.array([a_wins, b_wins])
    
    beta_tally = float(parameters["beta_tally"])
    z_tally = beta_tally * (scores_tally - np.max(scores_tally))
    e_tally = np.exp(z_tally)
    p_tally_core = e_tally / np.sum(e_tally)
    
    # Mixture
    p_ttb_weight = float(parameters["p_ttb"])
    p_mixed = p_ttb_weight * p_ttb_core + (1.0 - p_ttb_weight) * p_tally_core
    
    # Lapse rate
    epsilon = float(parameters["epsilon"])
    p_final = (1.0 - epsilon) * p_mixed + epsilon * np.array([0.5, 0.5])
    
    return p_final


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_5)

### DESIGN
**Validities (n_features=6):** [0.95, 0.9, 0.85, 0.55, 0.5, 0.5]

**Trial pairs (n=5):**
  trial 1: A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  trial 2: A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  trial 3: A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  trial 4: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  trial 5: A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]

**Rationale:** This design quantitatively dissociates the Sequential Evidence Accumulation (SEA) model from the Strategy Mixture (Take-The-Best + Tallying) model by exploiting their different tie-breaking and stopping rules. We use 6 features with a specific validity profile: one very high validity (0.95), two high validities (0.90, 0.85), and three low validities (0.55, 0.50, 0.50). In Trials 1 and 2, Tallying sees a perfect tie (3 vs 3), forcing the Mixture model to default entirely to TTB, which strictly follows the 0.95 cue. However, SEA (with a high threshold and gamma near 1) integrates all evidence and correctly calculates that the sum of the two high validities plus one low validity (0.90+0.85+0.55=2.30) outweighs the highest validity plus two low validities (0.95+0.50+0.50=1.95), leading to the opposite prediction. In Trials 3 and 4, one option has a massive Tallying advantage (5 vs 1) but loses on the most valid cue. The Mixture model overwhelmingly predicts the Tallying winner. In contrast, SEA with a low threshold (e.g., theta = 0.8) will terminate search immediately after the first cue, predicting the TTB winner and ignoring the remaining cues entirely.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
The Sequential Evidence Accumulation (SEA) model uses a unified deterministic mechanism (with softmax noise). Whether it stops early (acting like TTB) or integrates all cues (acting like Tallying), it strongly commits to one option per trial type, producing extreme choice probabilities (near 0 or 1). In contrast, the Strategy Mixture model posits that subjects stochastically switch between TTB and Tallying from trial to trial. Because the probability of using TTB is constrained between 10% and 50%, the Mixture model's predicted choice probabilities are an intermediate blend of the two heuristics. By calculating the empirical probability of choosing the TTB winner for each trial type and measuring its absolute deviation from 0.5, we can robustly separate the models: SEA will show a high deviation (~0.4) due to its extreme probabilities, while the Mixture model will show a significantly lower deviation (~0.15) due to its intermediate, blended probabilities.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # The most valid cue (cue 0) always discriminates in this design.
    # Determine the Take-The-Best (TTB) winner for each trial (0 for A, 1 for B).
    a_v0 = data['option_a_ratings'].apply(lambda x: x[0])
    b_v0 = data['option_b_ratings'].apply(lambda x: x[0])
    ttb_winner = (b_v0 > a_v0).astype(int)
    
    # Record whether the subject chose the TTB winner
    chose_ttb = (data['response'] == ttb_winner).astype(float)
    
    # Create a safe, hashable string identifier for each unique trial type
    trial_id = data['option_a_ratings'].apply(lambda x: "".join([str(v) for v in x])) + "_" + \
               data['option_b_ratings'].apply(lambda x: "".join([str(v) for v in x]))
               
    df_temp = pd.DataFrame({
        'subject_id': data['subject_id'],
        'trial_id': trial_id,
        'chose_ttb': chose_ttb
    })
    
    # Calculate the proportion of times the TTB winner was chosen per subject, per trial type
    means = df_temp.groupby(['subject_id', 'trial_id'])['chose_ttb'].mean()
    
    # Metric: Mean absolute deviation of these choice probabilities from 0.5
    return float((means - 0.5).abs().mean())


### RESULTS
- Predicted under pi_5 (simulated): 0.2899 (var=0.0082)
- Predicted under pi_4 (simulated): 0.1528 (var=0.0021)
- Observed on real data: 0.1619 (var=0.0032)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.85, 0.6, 0.55]

**Trial pairs (n=4):**
  trial 1: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Rationale:** To quantitatively dissociate the Strategy Mixture model (Take-The-Best + Tallying) from Sequential Evidence Accumulation (SEA), we exploit how the two models handle ties in Tallying and conflicting cue magnitudes. In Strategy Mixture, a Tallying tie causes the model to default entirely to the TTB prediction (scaled by p_ttb), yielding a moderate but robust preference for the option favored by the highest validity cue. In Trial 1 and 2, Option A wins the highest validity cue and a low validity cue, while Option B wins two very high validity cues. Tallying sees a perfect tie (2 vs 2), so the Mixture model strictly predicts Option A. However, SEA (with a high threshold to avoid early stopping) integrates all evidence and calculates that B's cues significantly outweigh A's, predicting Option B. If SEA uses a low threshold, it mimics TTB and strongly predicts A (unlike the Mixture's moderate prediction). Further trials pit a Tallying advantage against a TTB advantage to constrain the parameter space of both models.

**Computed schedule:** 4 unique pairs × 24 reps = 96 trials per subject.



### METRIC
Rationale:
This metric evaluates the difference in the probability of choosing Option A between Trial 2 and Trial 4. In the Strategy Mixture model, these two trials are structurally identical for both heuristics: Take-The-Best stops at the first cue and favors B in both trials, and Tallying counts 3 positive cues for A and 2 for B in both trials. Because both heuristics yield identical scores across the two trials, the Mixture model predicts that P(A|T2) - P(A|T4) is exactly 0.0, with zero true between-subject variance. In contrast, the Sequential Evidence Accumulation (SEA) model integrates all cues (for high threshold subjects). The evidence for A in T2 (+v1 -v4) is strictly greater than the evidence for A in T4 (-v1 +v4) because cue 1 has higher validity than cue 4. Thus, SEA reliably predicts P(A|T2) > P(A|T4). This creates a perfect discrimination where the Mixture model is anchored at zero while SEA produces a positive difference.

Source:
def metric(data: pd.DataFrame) -> float:
    # Project list representations to strings for safe masking
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
    t2_mask = a_str == '01110'
    # Trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
    t4_mask = a_str == '00111'
    
    # Calculate probability of choosing Option A (response == 0)
    p_a_t2 = (data.loc[t2_mask, 'response'] == 0).mean() if t2_mask.any() else 0.5
    p_a_t4 = (data.loc[t4_mask, 'response'] == 0).mean() if t4_mask.any() else 0.5
    
    # Return the difference in probability of choosing A
    return float(p_a_t2 - p_a_t4)

### RESULTS
- Predicted under pi_5 (simulated): 0.2400 (var=0.0939)
- Predicted under pi_4 (simulated): 0.0142 (var=0.0162)
- Observed on real data: 0.0683 (var=0.0514)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    preds = []
    for i in range(len(data)):
        p = -1
        for j in range(4):
            if a[i, j] > b[i, j]:
                p = 0
                break
            elif b[i, j] > a[i, j]:
                p = 1
                break
        preds.append(p)
        
    preds = np.array(preds)
    return float(np.mean(data['response'] == preds))
```

**Observed (real) value:** 0.4850 (var=0.0051)
**Predicted under pi_5:** 0.4838 (var=0.0461)
**Predicted under pi_4:** 0.4435 (var=0.0063)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    diff = a - b
    # The first index where features differ (since validities are strictly descending)
    first_diff_idx = np.argmax(diff != 0, axis=1)
    ttb_val = diff[np.arange(len(diff)), first_diff_idx]
    ttb_winner = np.where(ttb_val == 1, 0, 1)
    
    a_wins = np.sum(diff == 1, axis=1)
    b_wins = np.sum(diff == -1, axis=1)
    
    valid_mask = (a_wins != b_wins)
    tally_winner = np.where(a_wins > b_wins, 0, 1)
    
    # Focus only on trials where Tallying and Take The Best make strictly opposite predictions
    conflict_mask = valid_mask & (ttb_winner != tally_winner)
    
    if not np.any(conflict_mask):
        return 0.5
        
    responses = data['response'].values
    ttb_matches = np.sum(responses[conflict_mask] == ttb_winner[conflict_mask])
    
    return float(ttb_matches / np.sum(conflict_mask))

```

**Observed (real) value:** 0.3844 (var=0.0082)
**Predicted under pi_5:** 0.3833 (var=0.0897)
**Predicted under pi_4:** 0.3558 (var=0.0123)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    ties = []
    for a, b in zip(data['option_a_ratings'], data['option_b_ratings']):
        a_w = sum(1 for x, y in zip(a, b) if x > y)
        b_w = sum(1 for x, y in zip(a, b) if y > x)
        ties.append(a_w == b_w)
        
    tie_data = data[ties]
    if len(tie_data) == 0:
        return 0.5
        
    # In tie trials, A is designed to have higher-validity features than B.
    # Tallying predicts 50% A (response == 0) because the tallies are tied.
    # WADD predicts > 50% A because A's WADD score is higher.
    return float(np.mean(tie_data['response'] == 0))
```

**Observed (real) value:** 0.5667 (var=0.0123)
**Predicted under pi_5:** 0.6578 (var=0.0216)
**Predicted under pi_4:** 0.6022 (var=0.0106)

### Experiment 6
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Project option_a_ratings to string for hashability and comparison
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    
    # Trial 1 is uniquely identified by Option A having exactly these ratings
    t1_mask = a_str == '00111'
    
    if t1_mask.sum() == 0:
        return 0.0
        
    # Return the proportion of times Option B was chosen on this trial
    return float(data.loc[t1_mask, 'response'].mean())
```

**Observed (real) value:** 0.5000 (var=0.0450)
**Predicted under pi_5:** 0.6617 (var=0.0740)
**Predicted under pi_4:** 0.3567 (var=0.0383)

### Experiment 7
**Design**
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np

    a_tuples = data['option_a_ratings'].apply(tuple)
    b_tuples = data['option_b_ratings'].apply(tuple)
    
    is_trial_1 = (a_tuples == (0, 1, 1, 0)) & (b_tuples == (1, 0, 0, 1))
    is_trial_7 = (a_tuples == (1, 0, 0, 1)) & (b_tuples == (0, 1, 1, 0))
    
    wadd_choices = 0
    total_trials = 0
    
    if is_trial_1.sum() > 0:
        wadd_choices += (data.loc[is_trial_1, 'response'] == 0).sum()
        total_trials += is_trial_1.sum()
        
    if is_trial_7.sum() > 0:
        wadd_choices += (data.loc[is_trial_7, 'response'] == 1).sum()
        total_trials += is_trial_7.sum()
        
    if total_trials == 0:
        return 0.5
        
    return float(wadd_choices / total_trials)
```

**Observed (real) value:** 0.4600 (var=0.0252)
**Predicted under pi_5:** 0.4733 (var=0.0382)
**Predicted under pi_4:** 0.3725 (var=0.0117)

### Experiment 8
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A=[1, 0, 0, 1, 0], B=[0, 1, 1, 0, 0]
    # Mixture predicts A (0), WADD predicts B (1)
    t1_match = (a_str == '10010') & (data['response'] == 0)
    
    # Trial 2: A=[0, 1, 1, 0, 0], B=[1, 0, 0, 0, 1]
    # Mixture predicts B (1), WADD predicts A (0)
    t2_match = (a_str == '01100') & (data['response'] == 1)
    
    valid_trials = (a_str == '10010') | (a_str == '01100')
    
    if valid_trials.sum() == 0:
        return 0.5
        
    return float((t1_match.sum() + t2_match.sum()) / valid_trials.sum())
```

**Observed (real) value:** 0.4475 (var=0.0246)
**Predicted under pi_5:** 0.5081 (var=0.0288)
**Predicted under pi_4:** 0.6181 (var=0.0121)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the 8 experiments, Theory 1 (Sequential Evidence Accumulation, pi_5) generally outperforms Theory 2 (Strategy Mixture, pi_4) on a majority of the datasets (Experiments 3, 4, 7, and 8). Theory 2 performs exceptionally well on Experiment 1 and decently on Experiment 2 and 5, but completely fails to capture the variance and point estimates in the rest. Theory 1's main failure points are Experiments 1 and 2, where it over-predicts the extremity of choices. The Strategy Mixture model is too rigid in its assumption of a strict dichotomy between TTB and Tallying, failing to capture nuances where subjects might employ intermediate integration strategies. However, Theory 1 also fails to capture the exact blend of heuristics seen in Experiments 1 and 2. Therefore, Theory 2 should be replaced with a new theory that can bridge the gap.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Leaky Competing Accumulator' or 'Parallel Cue Integration with Discounting' theory. Instead of a strict mixture of two heuristics (TTB and Tallying) or a strict sequential search, this theory should posit that all cues are processed in parallel, but the evidence provided by each cue is discounted by its rank or by the presence of conflicting higher-validity cues. This allows for a soft blending of compensatory and non-compensatory decision-making without relying on a rigid stochastic mixture, potentially capturing the moderate choice probabilities in Experiments 1 and 2 while maintaining the robust performance of integration models in Experiments 3, 4, 7, and 8."
}
```

## Usage

```json
{
  "prompt_token_count": 8285,
  "candidates_token_count": 368,
  "total_token_count": 9365
}
```
