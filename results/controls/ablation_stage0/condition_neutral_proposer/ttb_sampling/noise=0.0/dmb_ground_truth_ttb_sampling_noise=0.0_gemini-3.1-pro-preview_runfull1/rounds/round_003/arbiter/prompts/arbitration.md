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
Take The Best (TTB) posits that decision-makers consider features sequentially in order of their subjective validities and stop searching as soon as they find a feature that discriminates between the two options. The choice is then based entirely on this single cue, providing a non-compensatory heuristic alternative to compensatory models like WADD.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort indices by validity in descending order
    order = np.argsort(validities)[::-1]
    
    a_wins = False
    b_wins = False
    
    # Search for the first discriminating cue
    for idx in order:
        if stim[0, idx] > stim[1, idx]:
            a_wins = True
            break
        elif stim[1, idx] > stim[0, idx]:
            b_wins = True
            break
            
    if a_wins:
        p_core = np.array([1.0, 0.0])
    elif b_wins:
        p_core = np.array([0.0, 1.0])
    else:
        p_core = np.array([0.5, 0.5])
        
    epsilon = float(parameters["epsilon"])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)

## THEORY 2 — pi_4
Probabilistic Take The Best (PTTB) posits that decision-makers search through features sequentially in order of their subjective validities. However, unlike deterministic Take The Best, the stopping rule is stochastic: upon finding a feature that discriminates between the two options, the decision-maker stops and bases their choice on that feature with probability gamma. If they do not stop, they continue to the next feature. If all features are evaluated without a decision, they guess randomly. This model captures the primarily non-compensatory nature of human decision-making while allowing for occasional deviations where lower-validity cues might influence the choice.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"PTTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort indices by validity in descending order
    order = np.argsort(validities)[::-1]
    
    gamma = float(parameters["gamma"])
    epsilon = float(parameters["epsilon"])
    
    p_choice = np.array([0.0, 0.0])
    p_reach = 1.0
    
    # Search for discriminating cues with stochastic stopping
    for idx in order:
        if stim[0, idx] > stim[1, idx]:
            p_stop = gamma
            p_choice += p_reach * p_stop * np.array([1.0, 0.0])
            p_reach *= (1.0 - p_stop)
        elif stim[1, idx] > stim[0, idx]:
            p_stop = gamma
            p_choice += p_reach * p_stop * np.array([0.0, 1.0])
            p_reach *= (1.0 - p_stop)
            
    # If no decision is made after evaluating all cues, guess
    p_choice += p_reach * np.array([0.5, 0.5])
        
    # Apply uniform lapse rate
    return (1.0 - epsilon) * p_choice + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 6: A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 7: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 8: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 9: A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  trial 10: A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 11: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 12: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]

**Rationale:** To distinguish deterministic Take The Best (TTB) from Probabilistic Take The Best (PTTB), we exploit PTTB's stochastic stopping rule. While TTB strictly terminates search at the first discriminating feature, PTTB may skip it (with probability 1 - gamma) and continue to evaluate subsequent features. We design trials where the highest-validity discriminating feature strongly favors one option, but all or most subsequent discriminating features favor the opposite option. TTB will consistently choose the option favored by the first discriminating cue (subject only to a uniform lapse rate), whereas PTTB will systematically deviate toward the opposite option whenever it skips the first cue and stops on a subsequent one. By varying which feature is the first to discriminate (e.g., feature 1 vs. feature 2 or 3) and having the remaining features consistently point the other way, we can detect the characteristic 'leakage' of choices to the second-best cues predicted by PTTB but not TTB.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
To distinguish deterministic Take The Best (TTB) from Probabilistic Take The Best (PTTB), we compare trials where the first two discriminating cues point in the same direction ('Agree') versus opposite directions ('Oppose'). Both models align with the first cue at high rates, but PTTB's stochastic stopping rule causes a systematic drop in alignment on 'Oppose' trials because skipping the first cue leads to a contradicting second cue. Previous metrics failed because the small number of 'Agree' trials (16 per subject) introduced high binomial noise, inflating between-subject variance. To solve this, we compute the empirical Log Odds Ratio of alignment between Agree and Oppose trials, applying the Haldane-Anscombe correction (+0.5 to all counts). The logit transformation non-linearly amplifies the signal when PTTB's alignment approaches 100% on Agree trials, maximizing the mean difference between the theories. Simultaneously, the correction stabilizes the variance for TTB, ensuring a tight null distribution. This combination yields a highly discriminative metric that overcomes the small-sample noise.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    agree_aligned = 0
    agree_total = 0
    oppose_aligned = 0
    oppose_total = 0
    
    for _, row in data.iterrows():
        a_rat = np.array(row['option_a_ratings'])
        b_rat = np.array(row['option_b_ratings'])
        diff = a_rat - b_rat
        
        discr_idx = np.where(diff != 0)[0]
        if len(discr_idx) < 2:
            continue
            
        first_idx = discr_idx[0]
        second_idx = discr_idx[1]
        
        is_agree = (diff[first_idx] == diff[second_idx])
        
        first_favors_A = (diff[first_idx] > 0)
        chose_A = (row['response'] == 0)
        is_aligned = (first_favors_A == chose_A)
        
        if is_agree:
            agree_aligned += int(is_aligned)
            agree_total += 1
        else:
            oppose_aligned += int(is_aligned)
            oppose_total += 1
            
    if agree_total == 0 or oppose_total == 0:
        return 0.0
        
    # Haldane-Anscombe correction to handle 100% alignment and stabilize variance
    log_odds_agree = np.log((agree_aligned + 0.5) / (agree_total - agree_aligned + 0.5))
    log_odds_oppose = np.log((oppose_aligned + 0.5) / (oppose_total - oppose_aligned + 0.5))
    
    return float(log_odds_agree - log_odds_oppose)


### RESULTS
- Predicted under pi_3 (simulated): 0.0123 (var=1.0955)
- Predicted under pi_4 (simulated): 0.7541 (var=0.7043)
- Observed on real data: 0.1341 (var=0.5478)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 3: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 4: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To distinguish deterministic Take The Best (TTB) from Probabilistic Take The Best (PTTB), we exploit the stochastic stopping rule of PTTB. TTB stops strictly at the first discriminating cue, whereas PTTB has a probability (1 - gamma) of skipping the first discriminating cue and evaluating subsequent ones. We design trials where the first discriminating cue strongly favors one option, but all subsequent discriminating cues favor the other option. TTB will almost exclusively choose the option favored by the first cue, whereas PTTB will show a systematic shift toward the opposite option due to the probability of skipping the first cue and stopping on later cues. We also include control trials where multiple top cues favor the same option, where both models should make identical predictions.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the difference in the rate at which subjects choose the option favored by the *first* discriminating cue, conditional on whether the *second* discriminating cue agrees or disagrees with the first. For the deterministic Take The Best (TTB) model, the decision is strictly determined by the first discriminating cue, so the agreement of the second cue has no effect (the difference should be zero in expectation). For Probabilistic Take The Best (PTTB), subjects sometimes skip the first cue and rely on the second; thus, when the second cue agrees, they are more likely to make the same choice as the first cue, and when it disagrees, they are more likely to make the opposite choice (yielding a strongly positive difference).

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    agree_match = []
    disagree_match = []
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        disc_cues = []
        for i in range(5):
            if a[i] > b[i]:
                disc_cues.append(0)
            elif b[i] > a[i]:
                disc_cues.append(1)
                
        if len(disc_cues) >= 2:
            first = disc_cues[0]
            second = disc_cues[1]
            
            chose_first = (resp == first)
            
            if first == second:
                agree_match.append(chose_first)
            else:
                disagree_match.append(chose_first)
                
    if len(agree_match) == 0 or len(disagree_match) == 0:
        return 0.0
        
    return float(np.mean(agree_match) - np.mean(disagree_match))


### RESULTS
- Predicted under pi_3 (simulated): -0.0087 (var=0.0042)
- Predicted under pi_4 (simulated): 0.0831 (var=0.0043)
- Observed on real data: -0.0219 (var=0.0059)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_mat > b_mat, axis=1)
    b_wins = np.sum(b_mat > a_mat, axis=1)
    
    validities = np.array([0.95, 0.9, 0.6, 0.55, 0.5])
    a_wadd = a_mat @ validities
    b_wadd = b_mat @ validities
    
    tally_prefers_a = a_wins > b_wins
    tally_prefers_b = b_wins > a_wins
    wadd_prefers_a = a_wadd > b_wadd
    wadd_prefers_b = b_wadd > a_wadd
    
    disagree = (tally_prefers_a & wadd_prefers_b) | (tally_prefers_b & wadd_prefers_a)
    
    if not np.any(disagree):
        return 0.5
        
    tally_choice = np.where(tally_prefers_a, 0, 1)
    
    match = (data['response'].values[disagree] == tally_choice[disagree])
    return float(np.mean(match))
```

**Observed (real) value:** 0.1067 (var=0.0120)
**Predicted under pi_3:** 0.1250 (var=0.0106)
**Predicted under pi_4:** 0.0600 (var=0.0026)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_vals = np.stack(data['option_a_ratings'].values)
    b_vals = np.stack(data['option_b_ratings'].values)
    
    # Identify trials where Tallying and WADD make strictly opposing predictions.
    # Trial 1: A=[0,0,1,1,1], B=[1,1,0,0,0] -> Tallying prefers A, WADD prefers B
    is_trial_1 = (a_vals[:, 0] == 0) & (a_vals[:, 2] == 1) & (b_vals[:, 0] == 1) & (b_vals[:, 2] == 0)
    
    # Trial 2: A=[1,1,0,0,0], B=[0,0,1,1,1] -> Tallying prefers B, WADD prefers A
    is_trial_2 = (a_vals[:, 0] == 1) & (a_vals[:, 2] == 0) & (b_vals[:, 0] == 0) & (b_vals[:, 2] == 1)
    
    mask = is_trial_1 | is_trial_2
    if not mask.any():
        return 0.5
        
    responses = data['response'].values
    wadd_aligned = (is_trial_1 & (responses == 1)) | (is_trial_2 & (responses == 0))
    
    return float(wadd_aligned[mask].mean())
```

**Observed (real) value:** 0.8649 (var=0.0063)
**Predicted under pi_3:** 0.8764 (var=0.0064)
**Predicted under pi_4:** 0.8764 (var=0.0043)

### Experiment 5
**Design**
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Approximate log-odds weights for WADD based on validities [0.88, 0.73, 0.73, 0.62, 0.62, 0.62]
    w = np.array([1.9924, 0.9946, 0.9946, 0.4895, 0.4895, 0.4895])
    
    tally_matches = []
    
    for _, row in data.iterrows():
        A = np.array(row['option_a_ratings'])
        B = np.array(row['option_b_ratings'])
        
        # Tallying counts strict wins
        A_tally = np.sum(A > B)
        B_tally = np.sum(B > A)
        
        # WADD uses weighted sums
        A_wadd = np.sum(A * w)
        B_wadd = np.sum(B * w)
        
        # 0 for A, 1 for B, -1 for tie
        tally_pref = 0 if A_tally > B_tally else (1 if B_tally > A_tally else -1)
        wadd_pref = 0 if A_wadd > B_wadd else (1 if B_wadd > A_wadd else -1)
        
        # We only care about trials where the two models make opposite strict predictions
        if tally_pref != -1 and wadd_pref != -1 and tally_pref != wadd_pref:
            if row['response'] == tally_pref:
                tally_matches.append(1.0)
            else:
                tally_matches.append(0.0)
                
    if len(tally_matches) == 0:
        return 0.5
        
    return float(np.mean(tally_matches))
```

**Observed (real) value:** 0.1467 (var=0.0156)
**Predicted under pi_3:** 0.1233 (var=0.0056)
**Predicted under pi_4:** 0.1063 (var=0.0034)

### Experiment 6
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    validities = np.array([0.9, 0.8, 0.7, 0.6, 0.5333])
    weights = np.log(validities / (1.0 - validities))
    
    match_tally = []
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wadd = np.sum(a * weights)
        b_wadd = np.sum(b * weights)
        
        a_tally = np.sum(a > b)
        b_tally = np.sum(b > a)
        
        wadd_prefers_a = a_wadd > b_wadd + 1e-5
        wadd_prefers_b = b_wadd > a_wadd + 1e-5
        tally_prefers_a = a_tally > b_tally
        tally_prefers_b = b_tally > a_tally
        
        disagree = (wadd_prefers_a and tally_prefers_b) or (wadd_prefers_b and tally_prefers_a)
        
        if disagree:
            chose_a = (row['response'] == 0)
            chose_b = (row['response'] == 1)
            
            if tally_prefers_a and chose_a:
                match_tally.append(1.0)
            elif tally_prefers_b and chose_b:
                match_tally.append(1.0)
            else:
                match_tally.append(0.0)
                
    if len(match_tally) == 0:
        return 0.5
        
    return float(np.mean(match_tally))
```

**Observed (real) value:** 0.1133 (var=0.0069)
**Predicted under pi_3:** 0.1208 (var=0.0055)
**Predicted under pi_4:** 0.1542 (var=0.0050)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    mask = data['option_a_ratings'].apply(lambda x: sum(x)) == 1
    if not mask.any():
        return 0.0
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.1780 (var=0.0177)
**Predicted under pi_3:** 0.1330 (var=0.0053)
**Predicted under pi_4:** 0.1350 (var=0.0042)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.85, 0.75, 0.7, 0.65, 0.6])
    weights = np.log(validities / (1.0 - validities))
    
    A = np.vstack(data['option_a_ratings'].values)
    B = np.vstack(data['option_b_ratings'].values)
    
    score_a = A @ weights
    score_b = B @ weights
    
    wadd_pred = (score_b > score_a).astype(int)
    
    return float((data['response'].values == wadd_pred).mean())
```

**Observed (real) value:** 0.1713 (var=0.0123)
**Predicted under pi_3:** 0.1398 (var=0.0066)
**Predicted under pi_4:** 0.1288 (var=0.0044)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (Take The Best, TTB) consistently provides a better fit to the observed data than Theory 2 (Probabilistic Take The Best, PTTB). In Experiments 1 and 2, which were explicitly designed to detect PTTB's stochastic stopping rule (where subjects skip the first discriminating cue and rely on the second), the observed metrics were very close to zero. This strongly supports TTB's strict stopping rule over PTTB's predicted systematic leakage to secondary cues. TTB also matches or outperforms PTTB in the remaining experiments. Since PTTB's core assumption of stochastic stopping is not supported by the data, it should be replaced with a fundamentally different competing theory.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a classic compensatory model, such as the Weighted Additive (WADD) model, to serve as a strong baseline against TTB. Unlike TTB, which searches sequentially and stops at the first discriminating cue, WADD assumes that decision-makers evaluate all available cues, weight them by their validities (or log-odds), and integrate them into a single compensatory score for each option. This will provide a clear contrast between non-compensatory (TTB) and compensatory (WADD) decision strategies."
}
```

## Usage

```json
{
  "prompt_token_count": 8899,
  "candidates_token_count": 293,
  "total_token_count": 10147
}
```
