# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_7" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_7" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_7
Sequential Evidence Accumulation with Lateral Inhibition, Leak, and a Collapsing Decision Threshold: Decision-makers sample features sequentially with probability proportional to their validities. Options accumulate evidence subject to leak and lateral inhibition. To prevent indecision when evidence is mixed or tied, the decision threshold collapses over time (urgency signal). A highly valid cue can quickly cross the initially high threshold (mimicking Take-The-Best), but if early cues conflict, the threshold gradually lowers, forcing a decision based on the integrated evidence of later sampled cues (mimicking Tallying or WADD).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    a, b = stim[0], stim[1]
    
    gamma = float(parameters["gamma"])
    theta = float(parameters["theta"])
    inhibition = float(parameters["inhibition"])
    leak = float(parameters["leak"])
    collapse_rate = float(parameters["collapse_rate"])
    epsilon = float(parameters["epsilon"])
    
    # Sampling probability based on validity
    w = val ** gamma
    if np.sum(w) == 0:
        p_sample = np.ones_like(w) / len(w)
    else:
        p_sample = w / np.sum(w)
        
    n_sims = 2000
    max_steps = 100
    
    # Pre-sample all cues for all sims and steps for speed
    samples = np.random.choice(len(val), size=(n_sims, max_steps), p=p_sample)
    
    inc_a = a[samples]
    inc_b = b[samples]
    
    ea = np.zeros(n_sims)
    eb = np.zeros(n_sims)
    
    decided = np.zeros(n_sims, dtype=bool)
    winner = np.full(n_sims, -1)
    
    for step in range(max_steps):
        mask = ~decided
        if not np.any(mask):
            break
            
        curr_inc_a = inc_a[mask, step]
        curr_inc_b = inc_b[mask, step]
        
        # LCA update rule with lateral inhibition and leak
        new_ea = np.maximum(0.0, ea[mask] * (1.0 - leak) + curr_inc_a - inhibition * eb[mask])
        new_eb = np.maximum(0.0, eb[mask] * (1.0 - leak) + curr_inc_b - inhibition * ea[mask])
        
        ea[mask] = new_ea
        eb[mask] = new_eb
        
        # Collapsing threshold
        curr_theta = max(0.01, theta - step * collapse_rate)
        cross_a = new_ea >= curr_theta
        cross_b = new_eb >= curr_theta
        
        just_decided = cross_a | cross_b
        
        if np.any(just_decided):
            jd_indices = np.where(just_decided)[0]
            
            for idx in jd_indices:
                if cross_a[idx] and not cross_b[idx]:
                    winner_val = 0
                elif cross_b[idx] and not cross_a[idx]:
                    winner_val = 1
                else:
                    if new_ea[idx] > new_eb[idx]:
                        winner_val = 0
                    elif new_eb[idx] > new_ea[idx]:
                        winner_val = 1
                    else:
                        winner_val = np.random.choice([0, 1])
                
                orig_idx = np.where(mask)[0][idx]
                winner[orig_idx] = winner_val
                decided[orig_idx] = True

    undecided = ~decided
    if np.any(undecided):
        ea_un = ea[undecided]
        eb_un = eb[undecided]
        
        # For those that haven't crossed threshold, highest evidence wins
        ties = ea_un == eb_un
        win_un = np.where(ea_un > eb_un, 0, 1)
        if np.any(ties):
            win_un[ties] = np.random.choice([0, 1], size=ties.sum())
            
        winner[undecided] = win_un
        
    p_A = np.sum(winner == 0) / n_sims
    p_B = np.sum(winner == 1) / n_sims
    
    p = np.array([p_A, p_B])
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)

## THEORY 2 — pi_3
People make decisions by integrating all available information rather than stopping at the first discriminating cue or simply counting features. According to the Weighted Additive (WADD) theory, decision-makers evaluate each option by computing a sum of its features, weighted by the subjective validity of each feature. However, people may non-linearly amplify the importance of highly valid cues. To capture this, validities are exponentiated by a scaling parameter and then normalized, allowing the model to smoothly interpolate between highly compensatory (Tallying-like) and non-compensatory (TTB-like) decision strategies without shrinking the overall scale of the evidence. Choice probabilities are generated via a softmax function over the weighted sums, with an independent lapse rate for random guessing.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    val = val ** gamma
    val = val / np.sum(val)
    
    a, b = stim[0], stim[1]
    
    # Compute weighted sum of features for each option
    score_a = np.sum(val * a)
    score_b = np.sum(val * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the WADD scores
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


## EXPERIMENT 1 (proposed by pi_7)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 2: A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 5: A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 6: A=[1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** This design quantitatively dissociates Sequential Evidence Accumulation (SEA) from the Weighted Additive (WADD) theory by exploiting the 'Shared Cue Muting' effect. WADD computes a linear sum of exponentiated validities. Because its softmax choice rule depends only on the difference between the two options' scores, adding a shared positive feature to both options perfectly cancels out, leaving the predicted choice probabilities mathematically identical. In contrast, SEA accumulates evidence dynamically. When a highly valid feature is shared by both options, it is sampled frequently, simultaneously adding evidence to both accumulators. This shared excitation drives both options rapidly toward the decision threshold, causing early and often simultaneous threshold crossings. This premature stopping prevents the lower-validity distinguishing features from reliably separating the options, shifting SEA's choice probabilities significantly toward 50% compared to when the shared feature is absent. By pairing trials with and without a shared top cue, we create a strict test: WADD predicts identical probabilities across pair variations, whereas SEA predicts a strong regression to chance when the top cue is shared.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric directly tests the 'Shared Cue Muting' effect that fundamentally dissociates the two models. In the WADD model, choice probability depends strictly on the difference in weighted sums between the two options. Since adding a shared cue to both options adds the exact same value to both sums, the difference remains identical. Thus, WADD predicts that the distance of P(A) from 0.5 should be identical for pairs of trials differing only by a shared cue, yielding a metric value of exactly 0. In contrast, the Sequential Evidence Accumulation (SEA) model predicts that a highly valid shared cue will be sampled frequently, adding evidence to both accumulators simultaneously. This shared excitation drives both accumulators quickly toward the decision threshold, causing premature threshold crossings and reducing the influence of the remaining distinguishing cues. Consequently, SEA predicts a strong regression toward chance (0.5) when the top cue is shared, yielding a reliably positive metric value.

Source:
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['a_key'] = data['option_a_ratings'].apply(tuple)
    
    # response == 0 means Option A was chosen, so 1 - mean(response) is P(A)
    p_A = 1.0 - data.groupby('a_key')['response'].mean()
    
    # Trials without the shared top cue
    t1 = p_A.get((0, 1, 1, 0, 0), 0.5)
    t3 = p_A.get((0, 1, 0, 0, 0), 0.5)
    t5 = p_A.get((0, 1, 1, 1, 0), 0.5)
    
    # Trials with the shared top cue (Cue 0 = 1 for both options)
    t2 = p_A.get((1, 1, 1, 0, 0), 0.5)
    t4 = p_A.get((1, 1, 0, 0, 0), 0.5)
    t6 = p_A.get((1, 1, 1, 1, 0), 0.5)
    
    # Calculate the regression to chance (0.5) caused by the shared top cue
    diff1 = abs(t1 - 0.5) - abs(t2 - 0.5)
    diff2 = abs(t3 - 0.5) - abs(t4 - 0.5)
    diff3 = abs(t5 - 0.5) - abs(t6 - 0.5)
    
    return float(diff1 + diff2 + diff3)

### RESULTS
- Predicted under pi_7 (simulated): 0.1062 (var=0.0608)
- Predicted under pi_3 (simulated): -0.0700 (var=0.0394)
- Observed on real data: 0.0725 (var=0.0566)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** This design aims to dissociate the Weighted Additive (WADD) theory from Sequential Evidence Accumulation (SEA) by systematically varying the distribution of evidence across the cue hierarchy, pitting single highly-valid cues against coalitions of lower-validity cues. By presenting both extreme conflicts (e.g., Cue 1 vs Cues 2-5) and shifted conflicts (e.g., Cue 2 vs Cues 3-5), we can observe how each model scales evidence. WADD's exponentiation of validities naturally makes it more non-compensatory at lower levels of the hierarchy, whereas SEA's fixed absolute threshold and sequential sampling make it more compensatory at lower levels because individual lower-validity cues struggle to cross the threshold alone.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Measures the difference in the probability of choosing the single-cue Option A between Trial 6 (Cue 3 vs Cues 4 & 5) and Trial 1 (Cue 1 vs Cues 2, 3, 4, & 5). In WADD, the exponentiation parameter allows Option A to dominate Option B in Trial 6 at much lower levels of non-compensatoriness than in Trial 1, creating a distinct positive gap. SEA's sequential sampling processes these conflicts differently due to the collapsing threshold, likely leading to a different magnitude of this gap.

Source:
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    mask_t6 = (data['A_str'] == '00100') & (data['B_str'] == '00011')
    mask_t1 = (data['A_str'] == '10000') & (data['B_str'] == '01111')
    
    p_a_t6 = (data[mask_t6]['response'] == 0).mean() if mask_t6.sum() > 0 else 0.5
    p_a_t1 = (data[mask_t1]['response'] == 0).mean() if mask_t1.sum() > 0 else 0.5
    
    return float(p_a_t6 - p_a_t1)

### RESULTS
- Predicted under pi_7 (simulated): 0.0025 (var=0.0330)
- Predicted under pi_3 (simulated): -0.1988 (var=0.0731)
- Observed on real data: -0.1700 (var=0.2061)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_match_count = 0
    disagree_count = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        # TTB prediction
        ttb_winner = -1
        for j in range(len(a)):
            if a[j] > b[j]:
                ttb_winner = 0
                break
            elif b[j] > a[j]:
                ttb_winner = 1
                break
                
        # Tallying prediction
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = -1
            
        # Only consider trials where TTB and Tallying make opposite predictions
        if ttb_winner != -1 and tally_winner != -1 and ttb_winner != tally_winner:
            disagree_count += 1
            if row['response'] == ttb_winner:
                ttb_match_count += 1
                
    if disagree_count == 0:
        return 0.5
    return ttb_match_count / disagree_count

```

**Observed (real) value:** 0.7581 (var=0.0332)
**Predicted under pi_7:** 0.6416 (var=0.0448)
**Predicted under pi_3:** 0.6753 (var=0.0250)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]

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
        
        if a_wins > b_wins:
            tally_pref = 0
        elif b_wins > a_wins:
            tally_pref = 1
        else:
            continue
            
        matches.append(row['response'] == tally_pref)
        
    if len(matches) == 0:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.2506 (var=0.0294)
**Predicted under pi_7:** 0.3081 (var=0.0448)
**Predicted under pi_3:** 0.2033 (var=0.0222)

### Experiment 5
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[1, 1, 0, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.75, 0.65, 0.55])
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    diff = a_mat - b_mat
    
    # TTB prediction: heavily weights the first discriminating cue
    # Using powers of 10 ensures strict lexicographical ordering (TTB logic)
    weights = np.array([1000, 100, 10, 1])
    ttb_score = np.dot(diff, weights)
    ttb_pred = np.where(ttb_score > 0, 0, 1)
    
    # WADD prediction (with gamma=1, i.e., linear integration)
    wadd_score = np.dot(diff, val)
    wadd_pred = np.where(wadd_score > 0, 0, 1)
    
    # Identify trials where TTB and baseline WADD disagree
    divergent = ttb_pred != wadd_pred
    
    if not np.any(divergent):
        return 0.5
        
    responses = data['response'].values
    # Calculate proportion of choices matching TTB on these critical trials
    ttb_match = (responses[divergent] == ttb_pred[divergent]).mean()
    
    return float(ttb_match)
```

**Observed (real) value:** 0.7236 (var=0.0302)
**Predicted under pi_7:** 0.7058 (var=0.0359)
**Predicted under pi_3:** 0.7036 (var=0.0145)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float(data['response'].mean())
```

**Observed (real) value:** 0.3975 (var=0.0240)
**Predicted under pi_7:** 0.3588 (var=0.0302)
**Predicted under pi_3:** 0.3127 (var=0.0167)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    data = data.copy()
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    # Trials 1, 2, and 3 are conflict trials where TTB prefers A and WADD prefers B.
    target_trials = ['10000', '01000', '10100']
    df_conflict = data[data['a_str'].isin(target_trials)].copy()
    df_conflict['chose_A'] = (df_conflict['response'] == 0).astype(float)
    
    subj_vars = []
    for subj, subj_df in df_conflict.groupby('subject_id'):
        means = subj_df.groupby('a_str')['chose_A'].mean()
        if len(means) == 3:
            subj_vars.append(means.var(ddof=1))
            
    if not subj_vars:
        return 0.0
        
    return float(np.mean(subj_vars))
```

**Observed (real) value:** 0.0574 (var=0.0093)
**Predicted under pi_7:** 0.0177 (var=0.0003)
**Predicted under pi_3:** 0.0331 (var=0.0015)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    data['chose_A'] = 1 - data['response']
    
    t2_mask = (data['A_str'] == '10001') & (data['B_str'] == '01100')
    t5_mask = (data['A_str'] == '01001') & (data['B_str'] == '00110')
    
    p_a_t2 = data[t2_mask]['chose_A'].mean() if t2_mask.sum() > 0 else 0.5
    p_a_t5 = data[t5_mask]['chose_A'].mean() if t5_mask.sum() > 0 else 0.5
    
    return float(p_a_t2 - p_a_t5)
```

**Observed (real) value:** 0.0175 (var=0.0095)
**Predicted under pi_7:** 0.0725 (var=0.0232)
**Predicted under pi_3:** 0.1713 (var=0.0375)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_seq = data['option_a_ratings'].apply(tuple)
    b_seq = data['option_b_ratings'].apply(tuple)
    
    t1_a = (1, 0, 0, 0, 0)
    t1_b = (0, 1, 1, 1, 1)
    
    t4_a = (1, 1, 1, 1, 0)
    t4_b = (1, 1, 1, 0, 1)
    
    t1_mask1 = (a_seq == t1_a) & (b_seq == t1_b)
    t1_mask2 = (a_seq == t1_b) & (b_seq == t1_a)
    
    t4_mask1 = (a_seq == t4_a) & (b_seq == t4_b)
    t4_mask2 = (a_seq == t4_b) & (b_seq == t4_a)
    
    p_t1 = 0.0
    n_t1 = t1_mask1.sum() + t1_mask2.sum()
    if n_t1 > 0:
        chose_a_t1 = (t1_mask1 & (data['response'] == 0)) | (t1_mask2 & (data['response'] == 1))
        p_t1 = chose_a_t1.sum() / n_t1
        
    p_t4 = 0.0
    n_t4 = t4_mask1.sum() + t4_mask2.sum()
    if n_t4 > 0:
        chose_a_t4 = (t4_mask1 & (data['response'] == 0)) | (t4_mask2 & (data['response'] == 1))
        p_t4 = chose_a_t4.sum() / n_t4
        
    return float(p_t1 - p_t4)
```

**Observed (real) value:** 0.6875 (var=0.0691)
**Predicted under pi_7:** 0.0450 (var=0.1074)
**Predicted under pi_3:** 0.2250 (var=0.0842)

### Experiment 10
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    data['trial_str'] = data.apply(lambda row: ''.join(map(str, row['option_a_ratings'])) + '_' + ''.join(map(str, row['option_b_ratings'])), axis=1)
    
    t1 = '110000_001111'
    t2 = '001111_110000'
    t3 = '101000_010111'
    t4 = '010111_101000'
    
    data['chose_a'] = (data['response'] == 0).astype(float)
    subj_means = data.groupby(['subject_id', 'trial_str'])['chose_a'].mean().unstack()
    
    # Preference for the option with the top cue in Trial 1/2 vs Trial 3/4
    if t1 in subj_means.columns and t2 in subj_means.columns:
        pref_1 = (subj_means[t1] + (1.0 - subj_means[t2])) / 2.0
    else:
        return 0.0
        
    if t3 in subj_means.columns and t4 in subj_means.columns:
        pref_3 = (subj_means[t3] + (1.0 - subj_means[t4])) / 2.0
    else:
        return 0.0
        
    diff = pref_1 - pref_3
    
    if isinstance(diff, pd.Series):
        return float(diff.mean())
    return float(diff)
```

**Observed (real) value:** 0.0475 (var=0.1792)
**Predicted under pi_7:** 0.0938 (var=0.0070)
**Predicted under pi_3:** 0.0346 (var=0.0103)

### Experiment 11
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    
    def get_pA(a_str, b_str):
        mask1 = (data['A_str'] == a_str) & (data['B_str'] == b_str)
        mask2 = (data['A_str'] == b_str) & (data['B_str'] == a_str)
        chose_A = 0
        total = 0
        if mask1.sum() > 0:
            chose_A += (data.loc[mask1, 'response'] == 0).sum()
            total += mask1.sum()
        if mask2.sum() > 0:
            chose_A += (data.loc[mask2, 'response'] == 1).sum()
            total += mask2.sum()
        return chose_A / total if total > 0 else 0.5

    # Trial 1: Top cue (0.90) vs single opposing cue (0.85)
    pA_t1 = get_pA("10000", "01000")
    
    # Trial 4: Top cue (0.90) vs coalition of 4 opposing cues (0.85 + 0.80 + 0.75 + 0.70)
    pA_t4 = get_pA("10000", "01111")
    
    return float(pA_t1 - pA_t4)

```

**Observed (real) value:** -0.7263 (var=0.0321)
**Predicted under pi_7:** 0.2232 (var=0.0400)
**Predicted under pi_3:** 0.2379 (var=0.0708)

### Experiment 12
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify Trial 1 and Trial 3 based on option A's ratings
    t1_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 0, 0))
    t3_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 0, 0))
    
    if t1_mask.sum() == 0 or t3_mask.sum() == 0:
        return 0.0
        
    # response is 0 for A, 1 for B. So mean() is the proportion of choosing B.
    # We want the difference in proportion of choosing A: P(A | Trial 3) - P(A | Trial 1)
    # Which is (1 - m3) - (1 - m1) = m1 - m3
    m1 = data[t1_mask]['response'].mean()
    m3 = data[t3_mask]['response'].mean()
    
    return float(m1 - m3)
```

**Observed (real) value:** -0.0253 (var=0.2181)
**Predicted under pi_7:** -0.0768 (var=0.0133)
**Predicted under pi_3:** -0.3021 (var=0.0367)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Both Theory 1 (Sequential Evidence Accumulation) and Theory 2 (Weighted Additive) capture some of the variance across the experiments, with Theory 1 winning on Experiment 1 and Theory 2 winning on Experiment 2. However, both theories fail dramatically on Experiments 9 and 11. For instance, in Experiment 11, the observed metric is strongly negative (-0.7263), whereas both models predict positive values. This indicates a fundamental misunderstanding of how decision-makers evaluate options when a single highly valid cue competes against a coalition of multiple lower-validity cues, possibly pointing towards a dilution effect or a strategy shift that neither sequential accumulation nor simple exponentiated weighted sums can capture. Because neither theory can account for the full pattern of data, a brand-new theory is required.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a brand-new theory that can account for the anomalous results in Experiments 9 and 11. Consider a Dual-Process or Heuristic Toolbox theory where decision-makers adaptively switch between a non-compensatory strategy (like Take-The-Best) and a compensatory one (like Tallying) depending on the complexity of the choice or the variance in cue distribution. Alternatively, consider a Parallel Constraint Satisfaction model or an Evidence Dilution model where adding more low-validity features to an option paradoxically decreases its overall subjective value due to averaging rather than adding evidence."
}
```

## Usage

```json
{
  "prompt_token_count": 11159,
  "candidates_token_count": 325,
  "total_token_count": 12743
}
```
