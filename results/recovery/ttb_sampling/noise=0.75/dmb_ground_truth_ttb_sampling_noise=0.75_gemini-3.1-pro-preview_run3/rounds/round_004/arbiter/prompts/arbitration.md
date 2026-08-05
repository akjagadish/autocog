# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_5" and "pi_6") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_5" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_6" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_5
Threshold-based Sequential Search integrates the fast-and-frugal nature of Take-The-Best with the compensatory evidence accumulation of Weighted Additive (WADD) models. Decision-makers search through cues in descending order of their validity, maintaining a running tally of the evidence (weighted by each cue's validity). Instead of stopping at the very first discriminating cue, search terminates only when the absolute accumulated evidence exceeds an internal confidence threshold. If all cues are exhausted without reaching this threshold, the option with the higher accumulated evidence is chosen. This allows for fast, one-reason decisions when a highly valid cue strongly favors one option, while enabling compensatory behavior when early cues provide weak or conflicting evidence.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort cues in descending order of validity
    order = np.argsort(validities)[::-1]
    
    a, b = stim[0], stim[1]
    evidence = 0.0
    threshold = float(parameters["threshold"])
    
    # Sequential search with evidence accumulation
    for idx in order:
        diff = a[idx] - b[idx]
        evidence += diff * validities[idx]
        
        # Stop search if the confidence threshold is met or exceeded
        if abs(evidence) >= threshold:
            break
            
    # Convert accumulated evidence into discrete choice scores
    scores = np.zeros(2)
    if evidence > 0:
        scores[0] = 1.0
    elif evidence < 0:
        scores[1] = 1.0
        
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the scores
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Blend in uniform lapse
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_6
Probabilistic Stopping Sequential Search

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    order = np.argsort(validities)[::-1]
    
    a, b = stim[0], stim[1]
    evidence = 0.0
    
    threshold = float(parameters["threshold"])
    slope = float(parameters["slope"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    p_continue = 1.0
    p_A = 0.0
    
    # Sequential search with probabilistic stopping
    for i, idx in enumerate(order):
        diff = a[idx] - b[idx]
        evidence += diff * validities[idx]
        
        # Determine stopping probability at this step
        if i == len(order) - 1:
            p_stop = 1.0
        else:
            # Logistic function for stopping probability
            z = -slope * (abs(evidence) - threshold)
            z = np.clip(z, -50, 50)  # Prevent overflow
            p_stop = 1.0 / (1.0 + np.exp(z))
            
        p_stop_here = p_continue * p_stop
        p_continue *= (1.0 - p_stop)
        
        # Softmax choice probability if search stops at this step
        z_choice = -beta * evidence
        z_choice = np.clip(z_choice, -50, 50)
        p_A_given_stop = 1.0 / (1.0 + np.exp(z_choice))
        
        p_A += p_stop_here * p_A_given_stop
        
    p_B = 1.0 - p_A
    probs = np.array([p_A, p_B])
    
    # Blend in uniform lapse
    return (1.0 - epsilon) * probs + epsilon * 0.5


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 7: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 8: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Rationale:** To quantitatively dissociate Threshold-based Sequential Search (TSS) from Probabilistic Stopping Sequential Search (PSSS), we exploit the difference between deterministic and probabilistic stopping rules. TSS employs a hard threshold: search terminates exactly when accumulated evidence crosses this threshold. PSSS uses a soft, logistic stopping probability at each step. We use a 5-feature design with linearly descending validities. We design 'compensatory' trials that systematically vary the maximum accumulated evidence and the step at which it is reached (e.g., strong initial evidence for A followed by consistent evidence for B, versus a tie on the first cue followed by moderate evidence for A). TSS predicts a sharp, step-like change in choice probabilities across these trials depending on whether the hard threshold is crossed at step 1, step 2, etc. In contrast, PSSS predicts a smoother, graded change in choice probabilities because the stopping probability scales continuously with the evidence magnitude at each step.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
In Trial 1 (A=[1,0,0,0,0], B=[0,1,1,1,1]) and Trial 4 (A=[1,0,1,0,0], B=[0,1,0,1,1]), the first cue strongly favors A (evidence +0.9). In Threshold-based Sequential Search (TSS), if the threshold is <= 0.9, search stops immediately at cue 1 and A is chosen for BOTH trials. If the threshold > 0.9, search continues. In both trials, the maximum cumulative evidence never exceeds 0.9 again, so TSS searches to the end. At the end, both trials have negative cumulative evidence for A (-1.7 for Trial 1, -0.3 for Trial 4), so B is chosen. Thus, TSS predicts identical choice probabilities for Trial 1 and Trial 4 (P(A) difference is ~0). In contrast, Probabilistic Stopping Sequential Search (PSSS) is sensitive to the intermediate evidence. Trial 4 has much stronger intermediate evidence for A (+0.8 at step 3) compared to Trial 1 (-0.6 at step 3), leading to a higher probability of stopping and choosing A. Thus, PSSS predicts P(A | Trial 4) > P(A | Trial 1).

Source:
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    t1_mask = (data['A_str'] == '10000') & (data['B_str'] == '01111')
    t4_mask = (data['A_str'] == '10100') & (data['B_str'] == '01011')
    
    p_a_t1 = 1.0 - data.loc[t1_mask, 'response'].mean()
    p_a_t4 = 1.0 - data.loc[t4_mask, 'response'].mean()
    
    # If for some reason a subject has no trials of this type, fill with 0
    if pd.isna(p_a_t1):
        p_a_t1 = 0.5
    if pd.isna(p_a_t4):
        p_a_t4 = 0.5
        
    return float(p_a_t4 - p_a_t1)

### RESULTS
- Predicted under pi_5 (simulated): -0.0233 (var=0.0147)
- Predicted under pi_6 (simulated): 0.1200 (var=0.0306)
- Observed on real data: 0.0400 (var=0.0440)

## EXPERIMENT 2 (proposed by pi_6)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=14):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 4: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 7: A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  trial 8: A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  trial 9: A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 10: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 11: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 12: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 13: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 14: A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]

**Rationale:** To quantitatively dissociate Probabilistic Stopping Sequential Search (PSSS) from Threshold-based Sequential Search (TSS), we exploit the functional difference in their stopping rules. TSS employs a hard confidence threshold: search terminates abruptly when accumulated evidence crosses this specific value, leading to step-like changes in choice probabilities across trials. PSSS, on the other hand, evaluates a logistic stopping probability at each step, predicting a smoother, graded change in choices as evidence magnitude varies. We use a 5-feature design with linearly descending validities and construct trials that systematically manipulate the peak accumulated evidence at early steps (e.g., strong initial evidence for A that is later contradicted by B, versus a tie on the first cue followed by moderate evidence for A). TSS predicts stark, qualitative reversals depending on whether the hard threshold is met at step 1 or step 2, whereas PSSS predicts a continuous shift in choice probabilities reflecting the soft stopping mechanism.

**Computed schedule:** 14 unique pairs × 6 reps = 84 trials per subject.



### METRIC
Rationale:
We partition 11 of the 14 trials into 'Strong' trials (where the first two cues agree) and 'Weak' trials (where the first two cues disagree). In all 11 of these trials, Threshold-based Sequential Search (TSS) predicts that the option favored by the first cue will ALWAYS be chosen, regardless of the subject's threshold. This is because the accumulated evidence either triggers an early stop favoring the first cue, or the search proceeds to the end where the final tally still favors the first cue. Consequently, TSS predicts identical choice probabilities for the Cue 1 winner across both groups (expected difference = 0). In contrast, Probabilistic Stopping Sequential Search (PSSS) evaluates evidence continuously. In Strong trials, evidence rapidly accumulates to high magnitudes (+/- 1.7 by step 2), leading to early stopping with high confidence. In Weak trials, evidence drops to near zero at step 2, prolonging search and exposing the decision to intermediate reversals (where PSSS might stop and choose the wrong option) or ending with much weaker final evidence. Thus, PSSS predicts a significantly lower probability of choosing the Cue 1 winner in Weak trials compared to Strong trials, yielding a strong positive difference that cleanly discriminates the theories while utilizing a large pool of trials to minimize empirical variance.

Source:
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    
    strong_trials = {'11000', '11100', '00000', '11010', '00111', '11110'}
    weak_trials = {'10011', '10110', '01010', '10101', '01100'}
    
    is_strong = data['A_str'].isin(strong_trials)
    is_weak = data['A_str'].isin(weak_trials)
    
    cue1_winner = data['A_str'].apply(lambda x: 1 if x[0] == '0' else 0)
    chose_cue1 = (data['response'] == cue1_winner)
    
    p_strong = chose_cue1[is_strong].mean()
    p_weak = chose_cue1[is_weak].mean()
    
    if pd.isna(p_strong):
        p_strong = 0.5
    if pd.isna(p_weak):
        p_weak = 0.5
        
    return float(p_strong - p_weak)

### RESULTS
- Predicted under pi_5 (simulated): -0.0112 (var=0.0105)
- Predicted under pi_6 (simulated): 0.0659 (var=0.0062)
- Observed on real data: 0.0118 (var=0.0089)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify Trial 1 where Tallying and WADD strongly conflict
    # Trial 1: A=[1, 1, 0, 0, 0], B=[0, 0, 1, 1, 1]
    t1_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
    
    if t1_mask.sum() == 0:
        return 0.5
        
    # Return the proportion of times Option A was chosen on this trial.
    # Tallying predicts B (response == 1) because B has 3 positive features vs A's 2.
    # WADD predicts A (response == 0) because A's 2 features have higher total validity (1.85 vs 1.65).
    return float((data.loc[t1_mask, 'response'] == 0).mean())
```

**Observed (real) value:** 0.6300 (var=0.0262)
**Predicted under pi_5:** 0.8383 (var=0.0218)
**Predicted under pi_6:** 0.8033 (var=0.0224)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    def is_t1(x):
        return tuple(x) == (1, 1, 0, 0, 0)
        
    def is_t2(x):
        return tuple(x) == (0, 0, 1, 1, 1)
        
    m1 = data['option_a_ratings'].apply(is_t1)
    m2 = data['option_a_ratings'].apply(is_t2)
    
    r1 = data.loc[m1, 'response'].mean()
    r2 = data.loc[m2, 'response'].mean()
    
    if pd.isna(r1): r1 = 0.5
    if pd.isna(r2): r2 = 0.5
    
    return float(r2 - r1)
```

**Observed (real) value:** 0.1822 (var=0.0512)
**Predicted under pi_5:** 0.6667 (var=0.0904)
**Predicted under pi_6:** 0.6578 (var=0.0730)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    diff = a_ratings - b_ratings
    weights = np.array([10000, 1000, 100, 10, 1])
    score = diff @ weights
    
    ttb_choice = (score < 0).astype(int)
    matches = (data['response'] == ttb_choice).mean()
    
    return float(matches)
```

**Observed (real) value:** 0.6029 (var=0.0014)
**Predicted under pi_5:** 0.6846 (var=0.0369)
**Predicted under pi_6:** 0.6319 (var=0.0129)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Calculate the sum of positive features for options A and B
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Filter to trials where option B has more positive features than option A
    # In this specific design, these are the compensatory trials where the 
    # most valid cue favors A but the sheer number of lower-validity cues favors B.
    mask = sum_b > sum_a
    
    if mask.sum() == 0:
        return 0.0
        
    # Return the proportion of times option B (response == 1) was chosen
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.4006 (var=0.0048)
**Predicted under pi_5:** 0.3278 (var=0.0698)
**Predicted under pi_6:** 0.3475 (var=0.0175)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    agree_matches = 0
    agree_total = 0
    conflict_matches = 0
    conflict_total = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        resp = int(row['response'])
        
        # Find TTB winner
        ttb_winner = -1
        for i in range(5):
            if a[i] > b[i]:
                ttb_winner = 0
                break
            elif b[i] > a[i]:
                ttb_winner = 1
                break
        
        if ttb_winner == -1:
            continue
            
        # Find WADD winner
        wadd_a = np.sum(a * validities)
        wadd_b = np.sum(b * validities)
        if wadd_a > wadd_b:
            wadd_winner = 0
        elif wadd_b > wadd_a:
            wadd_winner = 1
        else:
            continue
            
        # Check if TTB and WADD agree or conflict
        if ttb_winner == wadd_winner:
            agree_total += 1
            if resp == ttb_winner:
                agree_matches += 1
        else:
            conflict_total += 1
            if resp == ttb_winner:
                conflict_matches += 1
                
    p_agree = agree_matches / agree_total if agree_total > 0 else 0.5
    p_conflict = conflict_matches / conflict_total if conflict_total > 0 else 0.5
    
    return float(p_agree - p_conflict)
```

**Observed (real) value:** -0.0185 (var=0.0133)
**Predicted under pi_5:** 0.2520 (var=0.1253)
**Predicted under pi_6:** 0.1450 (var=0.0198)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    # TTB favors A if the first differing cue is positive for A.
    # Using exponentially decreasing weights captures lexicographic order exactly for 5 binary features.
    powers = np.array([10000, 1000, 100, 10, 1])
    diff = a_mat - b_mat
    ttb_favors_a = (diff @ powers) > 0
    
    # WADD favors B if the weighted sum of cues is higher for B.
    wadd_a = a_mat @ validities
    wadd_b = b_mat @ validities
    wadd_favors_b = wadd_b > wadd_a
    
    # Identify compensatory conflict trials
    conflict_mask = ttb_favors_a & wadd_favors_b
    
    if not np.any(conflict_mask):
        return 0.0
        
    # Return the proportion of B choices on these conflict trials
    return float(np.mean(data['response'].values[conflict_mask]))

```

**Observed (real) value:** 0.4147 (var=0.0049)
**Predicted under pi_5:** 0.3700 (var=0.0943)
**Predicted under pi_6:** 0.3953 (var=0.0261)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_key'] = data['option_a_ratings'].apply(tuple)
    
    t3 = (1, 1, 0, 0, 0)
    t4 = (1, 1, 1, 0, 0)
    t7 = (0, 0, 1, 1, 1)
    t8 = (0, 0, 0, 1, 1)
    
    pA_t3 = (data[data['A_key'] == t3]['response'] == 0).mean()
    pA_t4 = (data[data['A_key'] == t4]['response'] == 0).mean()
    
    pB_t7 = (data[data['A_key'] == t7]['response'] == 1).mean()
    pB_t8 = (data[data['A_key'] == t8]['response'] == 1).mean()
    
    pA_t3 = pA_t3 if pd.notna(pA_t3) else 0.5
    pA_t4 = pA_t4 if pd.notna(pA_t4) else 0.5
    pB_t7 = pB_t7 if pd.notna(pB_t7) else 0.5
    pB_t8 = pB_t8 if pd.notna(pB_t8) else 0.5
    
    return float((pA_t4 - pA_t3) + (pB_t8 - pB_t7))
```

**Observed (real) value:** 0.0000 (var=0.0528)
**Predicted under pi_5:** -0.0150 (var=0.0494)
**Predicted under pi_6:** 0.0517 (var=0.0452)

### Experiment 10
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np

    # Identify the option that the Take-The-Best (TTB) heuristic would favor
    # (TTB relies entirely on the first cue since it has the highest validity)
    a0 = data['option_a_ratings'].apply(lambda x: x[0])
    b0 = data['option_b_ratings'].apply(lambda x: x[0])
    ttb_is_A = a0 > b0
    chose_ttb = ((ttb_is_A) & (data['response'] == 0)) | ((~ttb_is_A) & (data['response'] == 1))

    # Convert ratings to strings for exact trial matching
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))

    # Condition 1: TTB and WADD agree (Trial 6)
    # Both heuristics strongly favor the same option.
    t6 = (a_str == '11100') & (b_str == '00011')

    # Condition 2: TTB and WADD conflict, but TSS stops early (Trials 1 and 4)
    # The first two cues agree, so TSS accumulates 0.95 + 0.80 = 1.75 evidence.
    # Since the max threshold is 1.25, TSS *always* stops early and chooses the TTB option.
    # Strategy Mixture, however, integrates all cues for WADD, so WADD prefers the opposite option.
    t1_t4 = ((a_str == '11000') & (b_str == '00111')) | ((a_str == '00111') & (b_str == '11000'))

    rate_agree = chose_ttb[t6].mean()
    rate_conflict_early = chose_ttb[t1_t4].mean()

    if pd.isna(rate_agree) or pd.isna(rate_conflict_early):
        return 0.0

    # Return the difference in TTB adherence
    return float(rate_agree - rate_conflict_early)
```

**Observed (real) value:** 0.0383 (var=0.0204)
**Predicted under pi_5:** -0.0092 (var=0.0176)
**Predicted under pi_6:** 0.0117 (var=0.0166)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, both Threshold-based Sequential Search (THEORY 1) and Probabilistic Stopping Sequential Search (THEORY 2) struggle to accurately predict the observed metrics, particularly in Experiments 3, 4, and 7 where both models significantly overpredict the choice probabilities. While THEORY 2 (pi_6) performs slightly better on Experiments 5, 8, and 10, both models fail to capture the nuances of the data, predicting more extreme deterministic or smooth outcomes than what is observed. The consistent overprediction in conflict trials suggests that a purely sequential search mechanism (whether with hard or soft stopping rules) does not fully capture the decision-making process. The observed data exhibits intermediate choice probabilities that might be better explained by an intra-individual or inter-individual mixture of distinct strategies rather than a single sequential evidence accumulation process.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Strategy Mixture: Take-The-Best and WADD' theory. Instead of a single sequential search process, this theory should posit that decision-makers probabilistically alternate between two distinct strategies on any given trial: a purely non-compensatory Take-The-Best (TTB) heuristic and a fully compensatory Weighted Additive (WADD) strategy. By mixing these two extremes via a strategy-selection probability parameter, the model can naturally generate the intermediate choice probabilities observed in the data, particularly in trials where TTB and WADD conflict, avoiding the rigidly extreme predictions of the sequential search models."
}
```

## Usage

```json
{
  "prompt_token_count": 10651,
  "candidates_token_count": 336,
  "total_token_count": 11907
}
```
