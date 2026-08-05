# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_17" and "pi_15") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_17" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_15" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_17
Evidence Averaging Heuristic Theory: Decision-makers evaluate an option by taking the strict average of the validities of its active cues, rather than summing them. This naturally explains the 'less-is-more' effect, as adding weak cues to an option with strong cues drags down its overall average validity, severely penalizing it without the need for an explicit dilution or capacity parameter.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    lambda_val = float(parameters["lambda_val"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Non-linear transformation of validities
    w = val ** lambda_val
    
    n_a = np.sum(a)
    n_b = np.sum(b)
    
    # Strict average of active cues
    v_a = np.sum(w * a) / n_a if n_a > 0 else 0.0
    v_b = np.sum(w * b) / n_b if n_b > 0 else 0.0
    
    scores = np.array([v_a, v_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_15
Diminishing Returns and Cue Count Dilution Theory: Decision-makers evaluate options by integrating the validities of active cues, but they perceive validity through a concave transformation that reflects diminishing marginal returns for extremely high-validity cues. Furthermore, the total integrated evidence for an option is diluted by the raw count of its active features. This captures the heuristic that presenting 'more arguments' can reduce the perceived average strength of the evidence, penalizing options that rely on many weak cues without imposing a strict capacity limit or a hard zero-bound.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    val = np.asarray(parameters["validities"], dtype=float)
    
    a, b = stim[0], stim[1]
    
    lambda_val = float(parameters["lambda_val"])
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Concave transformation of validities for diminishing returns
    w = val ** lambda_val
    
    n_a = np.sum(a)
    n_b = np.sum(b)
    
    # Integrate evidence and dilute by the count of active features
    v_a = np.sum(w * a) / (n_a ** gamma) if n_a > 0 else 0.0
    v_b = np.sum(w * b) / (n_b ** gamma) if n_b > 0 else 0.0
    
    scores = np.array([v_a, v_b])
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_17)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=4):**
  trial 1: A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 2: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 4: A=[1, 0, 1, 0, 1]  B=[0, 1, 1, 1, 0]

**Rationale:** This design quantitatively dissociates the 'Evidence Averaging Heuristic Theory' (Advocated) from the 'Diminishing Returns and Cue Count Dilution Theory' (Competing) by exploiting their differing constraints on the non-linear scaling of validities. The Advocated theory allows for convex transformations of validities (lambda_val up to 10.0), whereas the Competing theory strictly enforces a concave or linear transformation (lambda_val <= 1.0) to model diminishing returns. By pairing options that have the exact same raw count of active cues AND the exact same sum of validities, but different variances in those validities (e.g., {0.95, 0.55} vs {0.85, 0.65}), both theories apply equal dilution to the two options. However, the Advocated theory's convex numerator can strictly prefer the high-variance option (Option A), whereas the Competing theory's concave numerator must strictly prefer the low-variance option (Option B) or predict a tie. Thus, any consistent preference for Option A can only be explained by the Advocated theory.

**Computed schedule:** 4 unique pairs × 24 reps = 96 trials per subject.



### METRIC
Rationale:
In all trial pairs, Option A and Option B have the exact same number of active cues and the exact same sum of raw validities, but Option A has a higher variance in those validities. The Competing Theory uses a concave transformation of validities (lambda_val <= 1.0), which mathematically guarantees that the sum of transformed validities for Option B will be greater than or equal to that of Option A, leading to a preference for B (or a tie). The Advocated Theory allows for a convex transformation (lambda_val up to 10.0), which can lead to a strong preference for Option A. Thus, the proportion of times Option A is chosen (response == 0) will be strictly bounded <= 0.5 under the Competing Theory, but can be significantly higher under the Advocated Theory.

Source:
def metric(data: pd.DataFrame) -> float:
    # response == 0 means Option A was chosen
    return (data['response'] == 0).mean()


### RESULTS
- Predicted under pi_17 (simulated): 0.6292 (var=0.0113)
- Predicted under pi_15 (simulated): 0.4933 (var=0.0023)
- Observed on real data: 0.1671 (var=0.0088)

## EXPERIMENT 2 (proposed by pi_15)

### DESIGN
**Validities (n_features=5):** [0.9, 0.9, 0.9, 0.9, 0.6]

**Trial pairs (n=4):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Rationale:** This design quantitatively dissociates 'Diminishing Returns and Cue Count Dilution Theory' (Advocated) from 'Evidence Averaging Heuristic Theory' (Competing) by exploiting the strict averaging rule of the Competing theory. Under the Competing theory, the subjective value of an option is exactly the average of its active cues' non-linearly scaled validities. Thus, an option with one 0.90 cue and an option with two (or three) 0.90 cues will have the exact same average, leading the Competing theory to strictly predict a tie (50% choice probability) on Trials 1 and 2 regardless of its parameters. In contrast, the Advocated theory parameterizes dilution via gamma; depending on gamma, it can predict a strong preference for either the single cue or the multiple cues. Furthermore, on Trial 4, adding a 0.60 cue to two 0.90 cues strictly drags down the average, forcing the Competing theory to prefer the option with only two 0.90 cues. The Advocated theory, however, can evaluate this additively (if gamma is low), predicting a preference for the option with three cues.

**Computed schedule:** 4 unique pairs × 24 reps = 96 trials per subject.



### METRIC
Rationale:
On Trials 1 and 2, Option A has one 0.90 cue and Option B has two or three 0.90 cues. The Competing theory strictly averages the validities, predicting a tie (50% choice probability) on these trials regardless of its parameters. Thus, any deviation from 0.5 is solely due to binomial noise, resulting in a small absolute deviation. The Advocated theory, however, dilutes the sum by the number of cues raised to gamma. Depending on gamma, it can strongly prefer A or B, leading to choice probabilities near 0 or 1. Taking the absolute deviation from 0.5 of each subject's choice proportion robustly captures this difference.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    # Identify trials 1 and 2: option A has exactly 1 active cue
    is_t12 = data['option_a_ratings'].apply(lambda x: sum(x) == 1)
    t12_data = data[is_t12]
    
    if len(t12_data) == 0:
        return 0.0
        
    # Compute each subject's proportion of choosing B
    subject_means = t12_data.groupby('subject_id')['response'].mean()
    
    # Return the mean absolute deviation from 0.5
    return float(np.mean(np.abs(subject_means - 0.5)))


### RESULTS
- Predicted under pi_17 (simulated): 0.0546 (var=0.0013)
- Predicted under pi_15 (simulated): 0.3346 (var=0.0106)
- Observed on real data: 0.3183 (var=0.0173)

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
**Predicted under pi_17:** 0.7697 (var=0.0143)
**Predicted under pi_15:** 0.6447 (var=0.0737)

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
**Predicted under pi_17:** 0.2381 (var=0.0122)
**Predicted under pi_15:** 0.3608 (var=0.0773)

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
**Predicted under pi_17:** 0.7760 (var=0.0177)
**Predicted under pi_15:** 0.6298 (var=0.0665)

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
**Predicted under pi_17:** 0.2856 (var=0.0133)
**Predicted under pi_15:** 0.3237 (var=0.0327)

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
**Predicted under pi_17:** 0.0111 (var=0.0001)
**Predicted under pi_15:** 0.0188 (var=0.0005)

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
**Predicted under pi_17:** -0.0125 (var=0.0381)
**Predicted under pi_15:** -0.0187 (var=0.0258)

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
**Predicted under pi_17:** 0.3400 (var=0.0319)
**Predicted under pi_15:** 0.1162 (var=0.1586)

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
**Predicted under pi_17:** 0.0271 (var=0.0072)
**Predicted under pi_15:** 0.0242 (var=0.0078)

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
**Predicted under pi_17:** -0.0737 (var=0.0146)
**Predicted under pi_15:** -0.0211 (var=0.1060)

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
**Predicted under pi_17:** -0.1316 (var=0.0277)
**Predicted under pi_15:** -0.0116 (var=0.0145)

### Experiment 13
**Design**
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
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
```

**Observed (real) value:** 0.0725 (var=0.0566)
**Predicted under pi_17:** 0.1850 (var=0.0500)
**Predicted under pi_15:** 0.0700 (var=0.0482)

### Experiment 14
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    mask_t6 = (data['A_str'] == '00100') & (data['B_str'] == '00011')
    mask_t1 = (data['A_str'] == '10000') & (data['B_str'] == '01111')
    
    p_a_t6 = (data[mask_t6]['response'] == 0).mean() if mask_t6.sum() > 0 else 0.5
    p_a_t1 = (data[mask_t1]['response'] == 0).mean() if mask_t1.sum() > 0 else 0.5
    
    return float(p_a_t6 - p_a_t1)
```

**Observed (real) value:** -0.1700 (var=0.2061)
**Predicted under pi_17:** -0.1162 (var=0.0267)
**Predicted under pi_15:** -0.0225 (var=0.0181)

### Experiment 15
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    is_t2 = (a_sums == 4) & (b_sums == 1)
    is_t3 = (a_sums == 1) & (b_sums == 4)
    
    # Probability of choosing A
    p_a_t2 = 1.0 - data.loc[is_t2, 'response'].mean()
    p_a_t3 = 1.0 - data.loc[is_t3, 'response'].mean()
    
    return float(p_a_t2 - p_a_t3)
```

**Observed (real) value:** -0.6683 (var=0.0841)
**Predicted under pi_17:** -0.5325 (var=0.0495)
**Predicted under pi_15:** -0.4608 (var=0.2694)

### Experiment 16
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_keys = data['option_a_ratings'].apply(tuple)
    b_keys = data['option_b_ratings'].apply(tuple)
    
    t1_mask = (a_keys == (1, 0, 0, 0, 0)) & (b_keys == (0, 1, 0, 0, 0))
    t2_mask = (a_keys == (1, 0, 1, 1, 1)) & (b_keys == (0, 1, 0, 0, 0))
    
    p_a_t1 = (data.loc[t1_mask, 'response'] == 0).mean()
    p_a_t2 = (data.loc[t2_mask, 'response'] == 0).mean()
    
    return float(p_a_t2 - p_a_t1)
```

**Observed (real) value:** 0.0100 (var=0.0081)
**Predicted under pi_17:** -0.4625 (var=0.0804)
**Predicted under pi_15:** -0.1408 (var=0.1108)

### Experiment 17
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Extract A's features as strings for easy matching
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A = [1, 0, 0, 0, 0]
    # Trial 2: A = [1, 0, 1, 1, 1]
    # Response is 0 if A, 1 if B. We want P(Choose A), which is 1.0 - response.mean()
    
    t1_data = data[a_str == '10000']
    t2_data = data[a_str == '10111']
    
    if len(t1_data) == 0 or len(t2_data) == 0:
        return 0.0
        
    prob_a_t1 = 1.0 - t1_data['response'].mean()
    prob_a_t2 = 1.0 - t2_data['response'].mean()
    
    return float(prob_a_t1 - prob_a_t2)
```

**Observed (real) value:** -0.0400 (var=0.0118)
**Predicted under pi_17:** 0.5700 (var=0.0478)
**Predicted under pi_15:** 0.2325 (var=0.1338)

### Experiment 18
**Design**
  A=[0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, map(int, x))))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, map(int, x))))
    
    trial_3_mask = (data['A_str'] == '10011') & (data['B_str'] == '01000')
    trial_1_mask = (data['A_str'] == '00011') & (data['B_str'] == '00010')
    
    p_a_3 = 1.0 - data.loc[trial_3_mask, 'response'].mean() if trial_3_mask.sum() > 0 else 0.5
    p_a_1 = 1.0 - data.loc[trial_1_mask, 'response'].mean() if trial_1_mask.sum() > 0 else 0.5
    
    return float(p_a_3 - p_a_1)
```

**Observed (real) value:** 0.0167 (var=0.0107)
**Predicted under pi_17:** -0.0767 (var=0.0470)
**Predicted under pi_15:** -0.0442 (var=0.0154)

### Experiment 19
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['b_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1_mask = (data['a_str'] == '10100') & (data['b_str'] == '01010')
    t2_mask = (data['a_str'] == '10001') & (data['b_str'] == '01010')
    
    def subj_metric(df):
        t1_resp = df.loc[t1_mask, 'response']
        t2_resp = df.loc[t2_mask, 'response']
        if len(t1_resp) == 0 or len(t2_resp) == 0:
            return 0.0
            
        p_a_t1 = (t1_resp == 0).mean()
        p_a_t2 = (t2_resp == 0).mean()
        
        # Weight by the subject's signal-to-noise ratio measured via T2.
        weight = max(0.0, p_a_t2 - 0.5)
        return float(weight * (p_a_t1 - p_a_t2))
        
    return float(data.groupby('subject_id').apply(subj_metric).mean())
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Predicted under pi_17:** 0.0032 (var=0.0007)
**Predicted under pi_15:** 0.0003 (var=0.0001)

### Experiment 20
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(str(int(v)) for v in x))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(str(int(v)) for v in x))
    
    # Trial 2: A=[0, 1, 0, 0, 0] (sum=0.9), B=[0, 0, 1, 1, 0] (sum=1.0)
    t2 = (a_str == '01000') & (b_str == '00110')
    # Trial 6: A=[0, 1, 0, 0, 0] (sum=0.9), B=[0, 0, 1, 1, 1] (sum=1.5)
    t6 = (a_str == '01000') & (b_str == '00111')
    
    target_trials = t2 | t6
    if not target_trials.any():
        return 0.5
        
    return float((data.loc[target_trials, 'response'] == 0).mean())
```

**Observed (real) value:** 0.5825 (var=0.0907)
**Predicted under pi_17:** 0.8106 (var=0.0175)
**Predicted under pi_15:** 0.6994 (var=0.0811)

### Experiment 21
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1 = data[(data['A_str'] == '10000') & (data['B_str'] == '01000')]
    t2 = data[(data['A_str'] == '10111') & (data['B_str'] == '01000')]
    
    p_a_t1 = 1.0 - t1['response'].mean() if len(t1) > 0 else 0.5
    p_a_t2 = 1.0 - t2['response'].mean() if len(t2) > 0 else 0.5
    
    return float(p_a_t2 - p_a_t1)
```

**Observed (real) value:** -0.0250 (var=0.0106)
**Predicted under pi_17:** -0.4017 (var=0.0477)
**Predicted under pi_15:** -0.2675 (var=0.1692)

### Experiment 22
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option A has many cues (including the top ones) and Option B has few cues
    # Trial 2: A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
    # Trial 4: A=[1, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
    mask = data['option_a_ratings'].apply(lambda x: sum(x) >= 4) & data['option_b_ratings'].apply(lambda x: sum(x) <= 2)
    # Return the proportion of times Option B was chosen
    return float(data[mask]['response'].mean())
```

**Observed (real) value:** 0.8386 (var=0.0093)
**Predicted under pi_17:** 0.7428 (var=0.0170)
**Predicted under pi_15:** 0.6168 (var=0.0988)

### Experiment 23
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate the number of active cues in Option A
    n_cues = data['option_a_ratings'].apply(sum)
    
    # Calculate the probability of choosing A for each number of cues
    p_a = 1.0 - data.groupby(n_cues)['response'].mean()
    
    # Ensure we have data for all 4 cue levels
    if not all(k in p_a for k in [1, 2, 3, 4]):
        return 0.0
        
    # Calculate consecutive differences in P(A)
    diffs = [p_a[k+1] - p_a[k] for k in [1, 2, 3]]
    
    # The metric is the difference between the maximum increase and the maximum decrease
    # Competing theory predicts a steady increase followed by a sharp drop (large max - min)
    # Advocated theory predicts a smooth curve with less extreme fluctuations in differences
    return float(np.max(diffs) - np.min(diffs))
```

**Observed (real) value:** 0.0650 (var=0.0165)
**Predicted under pi_17:** 0.3692 (var=0.0683)
**Predicted under pi_15:** 0.1967 (var=0.0321)

### Experiment 24
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    mask1 = (a_str == '110000') & (b_str == '001100')
    mask2 = (a_str == '001100') & (b_str == '110000')
    
    valid = mask1 | mask2
    if not valid.any():
        return 0.5
        
    subset = data[valid]
    m1 = mask1[valid]
    
    chose_A = np.where(m1, subset['response'] == 0, subset['response'] == 1)
    
    return float(np.mean(chose_A))
```

**Observed (real) value:** 0.1768 (var=0.0184)
**Predicted under pi_17:** 0.7600 (var=0.0264)
**Predicted under pi_15:** 0.6621 (var=0.0279)

### Experiment 25
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    t2_mask = (sum_a == 4) & (sum_b == 1)
    t4_mask = (sum_a == 2) & (sum_b == 5)
    
    p_a_t2 = 1.0 - data.loc[t2_mask, 'response'].mean() if t2_mask.any() else 0.5
    p_a_t4 = 1.0 - data.loc[t4_mask, 'response'].mean() if t4_mask.any() else 0.5
    
    return float(p_a_t4 - p_a_t2)
```

**Observed (real) value:** 0.7333 (var=0.0444)
**Predicted under pi_17:** 0.5067 (var=0.0546)
**Predicted under pi_15:** 0.2067 (var=0.3187)

### Experiment 26
**Design**
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data['a_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1 = data[data['a_str'] == '01000']['response']
    t2 = data[data['a_str'] == '11000']['response']
    t3 = data[data['a_str'] == '00100']['response']
    t4 = data[data['a_str'] == '01100']['response']
    
    p_a_1 = 1.0 - t1.mean() if len(t1) > 0 else 0.5
    p_a_2 = 1.0 - t2.mean() if len(t2) > 0 else 0.5
    p_a_3 = 1.0 - t3.mean() if len(t3) > 0 else 0.5
    p_a_4 = 1.0 - t4.mean() if len(t4) > 0 else 0.5
    
    return (p_a_2 - p_a_1) + (p_a_4 - p_a_3)
```

**Observed (real) value:** -0.0333 (var=0.0178)
**Predicted under pi_17:** -0.0217 (var=0.0416)
**Predicted under pi_15:** -0.0983 (var=0.0410)

### Experiment 27
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    data['A_tuple'] = data['option_a_ratings'].apply(tuple)
    t1 = (1, 0, 0, 0, 0, 0)
    t2 = (1, 0, 1, 0, 0, 0)
    t3 = (1, 0, 1, 1, 0, 0)
    t4 = (1, 0, 1, 1, 1, 1)
    
    subj_diffs = []
    for subj, df in data.groupby('subject_id'):
        r1 = df.loc[df['A_tuple'] == t1, 'response'].mean()
        r2 = df.loc[df['A_tuple'] == t2, 'response'].mean()
        r3 = df.loc[df['A_tuple'] == t3, 'response'].mean()
        r4 = df.loc[df['A_tuple'] == t4, 'response'].mean()
        
        early_rate = (r1 + r2) / 2.0
        late_rate = (r3 + r4) / 2.0
        subj_diffs.append(late_rate - early_rate)
        
    return float(np.mean(subj_diffs))
```

**Observed (real) value:** -0.0025 (var=0.0058)
**Predicted under pi_17:** 0.1121 (var=0.0115)
**Predicted under pi_15:** 0.0771 (var=0.0114)

### Experiment 28
**Design**
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0, 1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    validities = np.array([0.95, 0.95, 0.95, 0.9, 0.5, 0.8, 0.6, 0.7, 0.7, 0.7])
    # Use a high power to strongly emphasize the difference in extreme validities
    # which the Competing theory's convex weighting function strictly prefers.
    weights = validities ** 6
    
    # Calculate weighted sum for A and B
    a_w = data['option_a_ratings'].apply(lambda x: np.sum(np.array(x) * weights))
    b_w = data['option_b_ratings'].apply(lambda x: np.sum(np.array(x) * weights))
    
    # chosen option's weighted sum minus unchosen option's weighted sum
    chosen_w = np.where(data['response'] == 0, a_w, b_w)
    unchosen_w = np.where(data['response'] == 0, b_w, a_w)
    
    diff = chosen_w - unchosen_w
    
    # Calculate the mean difference for each subject
    subj_means = data.assign(diff=diff).groupby('subject_id')['diff'].mean()
    
    # Return the average across subjects
    return float(subj_means.mean())
```

**Observed (real) value:** -0.1523 (var=0.0014)
**Predicted under pi_17:** 0.0238 (var=0.0011)
**Predicted under pi_15:** -0.0030 (var=0.0006)

### Experiment 29
**Design**
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    return float(np.mean(data['response'] == 0))

```

**Observed (real) value:** 0.1804 (var=0.0164)
**Predicted under pi_17:** 0.6654 (var=0.0212)
**Predicted under pi_15:** 0.4898 (var=0.0029)

### Experiment 30
**Design**
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 1, 0]  B=[0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Trial 1 specifically compares A=[1, 0, 0, 1] (high variance) vs B=[0, 1, 1, 0] (low variance).
    # The Advocated theory (concave, diminishing returns) strictly prefers the low-variance option B.
    # The Competing theory (convex, amplified penalty) strictly prefers the high-variance option A.
    mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 1))
    if mask.sum() == 0:
        return 0.5
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.8867 (var=0.0084)
**Predicted under pi_17:** 0.2933 (var=0.0255)
**Predicted under pi_15:** 0.5150 (var=0.0116)

### Experiment 31
**Design**
  A=[1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def is_superset(a, b):
        return sum(b) > sum(a) and all(bv >= av for av, bv in zip(a, b))
    
    mask = [is_superset(a, b) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    
    if sum(mask) == 0:
        return 0.5
        
    return float(data[mask]['response'].mean())
```

**Observed (real) value:** 0.1700 (var=0.0135)
**Predicted under pi_17:** 0.2221 (var=0.0183)
**Predicted under pi_15:** 0.3488 (var=0.0592)

### Experiment 32
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    t1_mask = (a_sums == 1) & (b_sums == 1)
    t2_mask = (a_sums == 4) & (b_sums == 1)
    
    p_a_t1 = (data.loc[t1_mask, 'response'] == 0).mean()
    p_a_t2 = (data.loc[t2_mask, 'response'] == 0).mean()
    
    if pd.isna(p_a_t1):
        p_a_t1 = 0.5
    if pd.isna(p_a_t2):
        p_a_t2 = 0.5
        
    return float(p_a_t1 - p_a_t2)
```

**Observed (real) value:** 0.0200 (var=0.0095)
**Predicted under pi_17:** 0.6025 (var=0.0604)
**Predicted under pi_15:** 0.1267 (var=0.1457)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Theory 1 (pi_17) relies on strict averaging of cue validities, which completely fails in Experiment 2 (predicting 0.05 vs observed 0.31) and mispredicts Experiment 1 (predicting 0.62 vs observed 0.16). Theory 2 (pi_15) captures Experiment 2 perfectly but still fails on Experiment 1 by predicting a near-tie (0.49) when subjects strongly preferred Option B (0.16). The observed data across experiments shows complex, context-dependent integration that neither strict averaging nor simple cue-count dilution fully captures. In particular, the reversal of preference between high-variance and low-variance cue pairs depending on the exact cue ranks (as seen by comparing Exp 1 and Exp 30) suggests a rank-based or difference-based heuristic rather than independent non-linear scaling.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Lexicographic with Tolerance' or 'Cue-Difference Thresholding' theory. Instead of integrating all cues (with or without dilution), decision-makers compare options cue-by-cue in order of validity. However, unlike strict Take-The-Best, if the difference in validities or the presence of conflicting cues falls within a certain tolerance threshold, decision-makers treat the top cues as a 'tie' and move down to evaluate the remaining cues. This explains why an option with a slightly weaker top cue but much stronger secondary cues can win (Exp 1), while in other contexts the top cue strictly dominates. The model should introduce a tolerance parameter for cue comparisons."
}
```

## Usage

```json
{
  "prompt_token_count": 20170,
  "candidates_token_count": 368,
  "total_token_count": 21903
}
```
