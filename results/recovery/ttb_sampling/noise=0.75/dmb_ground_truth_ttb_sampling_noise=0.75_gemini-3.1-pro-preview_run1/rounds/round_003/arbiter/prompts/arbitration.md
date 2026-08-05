# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_5") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_5" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
Take The Best (TTB) with Probabilistic Stopping: Decision-makers use a lexicographic heuristic, ranking features by subjective validity and stopping at the first discriminating feature. However, rather than making a strictly deterministic choice based on this feature, the decision is probabilistic. The probability of choosing the winning option scales with the validity of that discriminating feature via a softmax function with a highly regularized inverse temperature (beta). This allows confidence to vary depending on how valid the deciding feature is, capturing empirical noise without relying entirely on a global random lapse rate.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    epsilon = float(parameters["epsilon"])
    beta = float(parameters["beta"])
    
    a, b = stim[0], stim[1]
    
    # Rank features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    scores = np.array([0.0, 0.0])
    
    # Iterate through sorted features to find the first discriminator
    for f in order:
        if a[f] > b[f]:
            scores = np.array([validities[f], 0.0])
            break
        elif b[f] > a[f]:
            scores = np.array([0.0, validities[f]])
            break
            
    # If no feature discriminates, default to uniform guessing
    if scores[0] == scores[1]:
        p_core = np.array([0.5, 0.5])
    else:
        # Probabilistic choice scaling with the validity of the discriminating feature
        z = beta * (scores - scores.max())
        e = np.exp(z)
        p_core = e / e.sum()
        
    # Apply lapse rate
    n_opts = 2
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_5
Probabilistic Cue Search: Decision-makers rely on a strict one-reason heuristic but search through cues probabilistically rather than in a fixed deterministic order. The probability of inspecting a cue is proportional to its subjective validity (via a softmax function). The decision-maker inspects cues one by one without replacement until a discriminating cue is found, which then deterministically dictates the choice. Mathematically (via the Independence of Irrelevant Alternatives in the Plackett-Luce model), the probability that a specific discriminating cue is the first one encountered is exactly its softmax weight divided by the sum of the softmax weights of all discriminating cues. This preserves the non-compensatory nature of the process while introducing cognitively plausible noise through stochastic attention and memory retrieval.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    a, b = stim[0], stim[1]
    
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Identify which cues discriminate between the two options
    disc = (a != b)
    
    if not np.any(disc):
        # If no cues discriminate, guess randomly
        p_core = np.array([0.5, 0.5])
    else:
        # Compute softmax weights for discriminating cues
        w = np.zeros_like(validities)
        max_v = np.max(validities[disc])
        w[disc] = np.exp(beta * (validities[disc] - max_v))
        
        sum_w = np.sum(w)
        
        # The probability of choosing an option is the sum of the weights 
        # of the discriminating cues that favor it, normalized by the sum
        # of weights of all discriminating cues.
        p_a = np.sum(w[a > b]) / sum_w
        p_b = np.sum(w[b > a]) / sum_w
        
        p_core = np.array([p_a, p_b])
        
    # Apply uniform lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probabilities = np.asarray(probs, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=9):**
  trial 1: A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 4: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 5: A=[1, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1]
  trial 6: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 7: A=[1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 8: A=[1, 1, 1, 0, 1]  B=[1, 1, 0, 1, 1]
  trial 9: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]

**Rationale:** To quantitatively dissociate TTB with Probabilistic Stopping (advocated) from Probabilistic Cue Search (competing), this design holds the highest-validity discriminating cue constant across subsets of trials while varying the number and distribution of lower-validity discriminating cues. Under the advocated TTB model, choice probability depends exclusively on the validity of the first (highest-validity) discriminating cue; thus, it predicts identical choice probabilities across all trials sharing the same top discriminating cue, regardless of other cue values. In contrast, the competing Probabilistic Cue Search model samples all discriminating cues proportionally to their validities. Therefore, adding lower-validity cues that favor the opposing option will systematically pull the choice probability away from the top cue's favored option under PCS, while leaving the TTB prediction completely unaffected.

**Computed schedule:** 9 unique pairs × 10 reps = 90 trials per subject.



### METRIC
Rationale:
This metric calculates the drop in the probability of choosing Option A when additional lower-validity cues are introduced that favor Option B, while the highest-validity discriminating cue (which favors Option A) remains constant. Under the advocated Take The Best (TTB) model, choice probability depends only on the highest-validity discriminating cue, so adding lower-validity cues favoring B has zero effect (expected metric ~ 0). Under the competing Probabilistic Cue Search (PCS) model, all discriminating cues are sampled proportionally to their validity, so adding cues favoring B substantially pulls the choice probability toward B (expected metric > 0).

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    data = data.copy()
    data['A_tuple'] = data['option_a_ratings'].apply(tuple)
    data['B_tuple'] = data['option_b_ratings'].apply(tuple)
    data['chose_A'] = (data['response'] == 0).astype(float)
    
    t1_a, t1_b = (1, 0, 1, 1, 1), (0, 1, 1, 1, 1)
    t3_a, t3_b = (1, 0, 0, 0, 0), (0, 1, 1, 1, 1)
    
    t5_a, t5_b = (1, 1, 0, 1, 1), (1, 0, 1, 1, 1)
    t6_a, t6_b = (1, 1, 0, 0, 0), (1, 0, 1, 1, 1)
    
    t8_a, t8_b = (1, 1, 1, 0, 1), (1, 1, 0, 1, 1)
    t9_a, t9_b = (1, 1, 1, 0, 0), (1, 1, 0, 1, 1)
    
    def get_pa(a, b):
        mask = (data['A_tuple'] == a) & (data['B_tuple'] == b)
        if mask.sum() == 0:
            return 0.5
        return data.loc[mask, 'chose_A'].mean()
        
    diff1 = get_pa(t1_a, t1_b) - get_pa(t3_a, t3_b)
    diff2 = get_pa(t5_a, t5_b) - get_pa(t6_a, t6_b)
    diff3 = get_pa(t8_a, t8_b) - get_pa(t9_a, t9_b)
    
    return float(diff1 + diff2 + diff3)

### RESULTS
- Predicted under pi_3 (simulated): 0.0020 (var=0.1186)
- Predicted under pi_5 (simulated): 0.3600 (var=0.2304)
- Observed on real data: -0.0680 (var=0.1734)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 5: A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 6: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 7: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 8: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 9: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  trial 10: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 11: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 12: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate Probabilistic Cue Search (advocated) from Take The Best with Probabilistic Stopping (competing), this design holds the highest-validity discriminating cue constant across subsets of trials while varying the number of lower-validity discriminating cues that favor the opposing option. Under the competing TTB model, choice probability is determined solely by the validity of the first (highest-validity) discriminating cue, predicting identical choice probabilities across all trials sharing the same top discriminator. In contrast, the advocated Probabilistic Cue Search model samples all discriminating cues proportionally to their validities. Thus, adding more lower-validity cues that favor the opposing option will systematically shift the choice probability away from the top cue's favored option under PCS, while leaving the TTB prediction completely unaffected.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the difference in the probability of choosing the option favored by the highest-validity discriminating cue between trials where the opposing option has only 1 discriminating cue in its favor versus trials where the opposing option has 3 or more discriminating cues in its favor. Under the Take The Best (TTB) theory, the choice is determined solely by the highest-validity discriminating cue, so the number of opposing cues should not affect the choice probability (yielding a metric near 0). Under the Probabilistic Cue Search (PCS) theory, all discriminating cues are sampled proportionally to their validities, meaning that adding more opposing cues will systematically pull the choice probability away from the top-cue option (yielding a significantly positive metric).

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    top_cue_chosen = []
    opposing_cues = []
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        top_cue_option = -1
        opp = 0
        for i in range(len(a)):
            if a[i] != b[i]:
                if top_cue_option == -1:
                    top_cue_option = 0 if a[i] == 1 else 1
                else:
                    if top_cue_option == 0 and b[i] == 1:
                        opp += 1
                    elif top_cue_option == 1 and a[i] == 1:
                        opp += 1
                        
        top_cue_chosen.append(1 if resp == top_cue_option else 0)
        opposing_cues.append(opp)
        
    df = pd.DataFrame({'top_chosen': top_cue_chosen, 'opp': opposing_cues})
    
    mean_low = df[df['opp'] == 1]['top_chosen'].mean()
    mean_high = df[df['opp'] >= 3]['top_chosen'].mean()
    
    if pd.isna(mean_low) or pd.isna(mean_high):
        return 0.0
        
    return float(mean_low - mean_high)

### RESULTS
- Predicted under pi_3 (simulated): -0.0192 (var=0.0085)
- Predicted under pi_5 (simulated): 0.1595 (var=0.0201)
- Observed on real data: 0.0013 (var=0.0233)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def get_dev(df):
        m3 = df['option_a_ratings'].apply(lambda x: tuple(int(v) for v in x)) == (1, 0, 0, 0, 0)
        m4 = df['option_a_ratings'].apply(lambda x: tuple(int(v) for v in x)) == (0, 1, 1, 0, 0)
        
        dev = 0.0
        count = 0
        if m3.sum() > 0:
            dev += abs((df.loc[m3, 'response'] == 0).mean() - 0.5)
            count += 1
        if m4.sum() > 0:
            dev += abs((df.loc[m4, 'response'] == 0).mean() - 0.5)
            count += 1
            
        return dev / count if count > 0 else 0.0

    return float(data.groupby('subject_id').apply(get_dev).mean())
```

**Observed (real) value:** 0.1217 (var=0.0056)
**Predicted under pi_3:** 0.1783 (var=0.0133)
**Predicted under pi_5:** 0.1358 (var=0.0072)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    count = 0
    match_trials = 0
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        sum_a = sum(a)
        sum_b = sum(b)
        
        # Isolate conflict trials where one option has fewer features (sum=2 vs sum=3)
        # but the fewer features include the most predictive one (index 0 is 1).
        if sum_a == 2 and sum_b == 3 and a[0] == 1:
            match_trials += 1
            if resp == 0:  # Chose the option with fewer but more valid features
                count += 1
        elif sum_b == 2 and sum_a == 3 and b[0] == 1:
            match_trials += 1
            if resp == 1:  # Chose the option with fewer but more valid features
                count += 1
                
    if match_trials == 0:
        return 0.0
    return count / match_trials
```

**Observed (real) value:** 0.6062 (var=0.0088)
**Predicted under pi_3:** 0.6200 (var=0.0141)
**Predicted under pi_5:** 0.7375 (var=0.0254)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    match_count = 0
    trial_count = 0
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        
        sa = sum(a)
        sb = sum(b)
        
        if sa == sb:
            continue
            
        ttb = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb = 0
                break
            elif b[i] > a[i]:
                ttb = 1
                break
                
        # Target "compensatory" trials where TTB chooses the option with fewer positive features
        if (ttb == 0 and sa < sb) or (ttb == 1 and sb < sa):
            trial_count += 1
            if row['response'] == ttb:
                match_count += 1
                
    if trial_count == 0:
        return 0.5
        
    return float(match_count / trial_count)
```

**Observed (real) value:** 0.5920 (var=0.0046)
**Predicted under pi_3:** 0.6173 (var=0.0123)
**Predicted under pi_5:** 0.5270 (var=0.0102)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    v = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    wadd_matches = []
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        resp = row['response']
        
        wadd_a = np.dot(a, v)
        wadd_b = np.dot(b, v)
        wadd_pred = 0 if wadd_a > wadd_b else 1
        
        diff = a - b
        ttb_pred = None
        for i in range(len(v)):
            if diff[i] == 1:
                ttb_pred = 0
                break
            elif diff[i] == -1:
                ttb_pred = 1
                break
                
        if ttb_pred is not None and wadd_pred != ttb_pred:
            wadd_matches.append(1 if resp == wadd_pred else 0)
            
    if not wadd_matches:
        return 0.5
        
    return float(np.mean(wadd_matches))
```

**Observed (real) value:** 0.4011 (var=0.0034)
**Predicted under pi_3:** 0.3628 (var=0.0139)
**Predicted under pi_5:** 0.4697 (var=0.0103)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def get_first_disc(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] != b[i]: return i
        return -1
        
    def get_ttb_choice(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]: return 0
            if b[i] > a[i]: return 1
        return -1
        
    def get_tally_diff(row):
        a = sum(row['option_a_ratings'])
        b = sum(row['option_b_ratings'])
        ttb = get_ttb_choice(row)
        if ttb == 0:
            return a - b
        elif ttb == 1:
            return b - a
        return 0

    first_disc = data.apply(get_first_disc, axis=1)
    tally_diffs = data.apply(get_tally_diff, axis=1)
    ttb_choices = data.apply(get_ttb_choice, axis=1)
    
    is_ttb_chosen = (data['response'] == ttb_choices)
    
    # Only look at trials where the first discriminating feature is feature 0
    mask_0 = first_disc == 0
    
    # Trials where Tallying agrees with TTB (Tally diff > 0)
    mask_agree = mask_0 & (tally_diffs > 0)
    # Trials where Tallying strongly disagrees with TTB (Tally diff < -1)
    mask_disagree = mask_0 & (tally_diffs < -1)
    
    if mask_agree.sum() == 0 or mask_disagree.sum() == 0:
        return 0.0
        
    return float(is_ttb_chosen[mask_agree].mean() - is_ttb_chosen[mask_disagree].mean())
```

**Observed (real) value:** 0.0333 (var=0.0361)
**Predicted under pi_3:** 0.0167 (var=0.0303)
**Predicted under pi_5:** 0.3133 (var=0.0429)

### Experiment 8
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate sum of features for A and B
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    # Conflict trials: Tallying prefers B (sum B > sum A)
    # Congruent trials: Tallying prefers A (sum A > sum B)
    conflict_mask = b_sums > a_sums
    congruent_mask = a_sums > b_sums
    
    # response == 1 means choosing B
    p_b_conflict = data.loc[conflict_mask, 'response'].mean()
    p_b_congruent = data.loc[congruent_mask, 'response'].mean()
    
    if np.isnan(p_b_conflict):
        p_b_conflict = 0.0
    if np.isnan(p_b_congruent):
        p_b_congruent = 0.0
        
    return float(p_b_conflict - p_b_congruent)
```

**Observed (real) value:** -0.0124 (var=0.0079)
**Predicted under pi_3:** -0.0009 (var=0.0098)
**Predicted under pi_5:** 0.2907 (var=0.0158)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed data strongly supports Theory 1 (Take The Best with Probabilistic Stopping) over Theory 2 (Probabilistic Cue Search). Experiments 1, 2, 7, and 8 explicitly tested whether the presence of multiple lower-validity discriminating cues favoring the opposing option pulls choice probabilities away from the option favored by the highest-validity cue. In all cases, the observed metrics were near zero, perfectly matching Theory 1's prediction that lower-validity cues are ignored once the top discriminating cue is found. Theory 2 consistently predicted large deviations that did not materialize in the human data. Since Theory 2's core assumption\u2014probabilistic sampling of all cues\u2014is falsified by the data, it should be replaced.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Strict Take-The-Best with Uniform Lapse' theory. This theory posits that decision-makers deterministically use the highest-validity discriminating cue (Strict TTB) on a given proportion of trials, and simply guess randomly on the remaining trials due to inattention. This serves as a simpler, parameter-efficient baseline compared to Theory 1's validity-scaled probabilistic stopping, testing if the complexity of scaling choice probability by cue validity is actually necessary to explain the data."
}
```

## Usage

```json
{
  "prompt_token_count": 8998,
  "candidates_token_count": 295,
  "total_token_count": 10222
}
```
