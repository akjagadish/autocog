# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_6" and "pi_5") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_6" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_5" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_6
Strict Alternation: Subjects in these experimental paradigms ignore all feature information and simply alternate their choices between Option A and Option B deterministically on every trial. This response heuristic reflects a complete lack of engagement with the stimulus validities, substituting a simple motor-alternation pattern.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    # Reference the dummy parameter to satisfy the parameter usage constraint
    _ = float(parameters["dummy"])
    
    # If first trial, guess randomly to start the sequence
    if len(history["response"]) == 0:
        return np.array([0.5, 0.5])
        
    # Otherwise, strictly alternate from the last response
    last_response = history["response"][-1]
    if last_response == 0:
        return np.array([0.0, 1.0])
    else:
        return np.array([1.0, 0.0])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_5
Response Heuristic / Spatial Bias: Subjects in these paradigms often ignore feature information entirely and instead rely on presentation-based response heuristics. Decision-making is driven by a persistent spatial bias (e.g., a preference for Option A over Option B) combined with a sequential dependence, such as a tendency to repeat the previous choice or alternate between options. This produces behavior that appears random with respect to cue validities but contains structured autocorrelation and spatial preference.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    beta_bias = float(parameters["beta_bias"])
    beta_repeat = float(parameters["beta_repeat"])
    
    # Determine the indicator for the previous choice
    # 1.0 if Option A was chosen, -1.0 if Option B was chosen, 0.0 if first trial
    if len(history["response"]) == 0:
        last_a = 0.0
    else:
        last_a = 1.0 if history["response"][-1] == 0 else -1.0
        
    # Logit for choosing Option A
    z = beta_bias + beta_repeat * last_a
    
    # Convert to probability using sigmoid
    p_a = 1.0 / (1.0 + np.exp(-z))
    
    return np.array([p_a, 1.0 - p_a])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_6)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 2: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 6: A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  trial 7: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 8: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 9: A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  trial 10: A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]

**Rationale:** Both the Strict Alternation (advocated) and Spatial Bias (competing) theories assume subjects completely ignore stimulus features. The key difference is that Strict Alternation predicts a deterministic sequence with exactly zero spatial bias, whereas the Spatial Bias model allows for a persistent preference for one option over the other alongside probabilistic sequential dependence. To ensure that any observed sequence effects or biases are purely response-driven and not artifacts of the stimuli, we use a perfectly symmetric and counterbalanced set of trial pairs. Every feature configuration presented for Option A is also presented identically for Option B across the experiment. This guarantees that any stimulus-driven model would predict a 50/50 overall choice rate and zero sequential dependence, allowing us to unambiguously isolate the deterministic alternation pattern from a probabilistic spatial bias.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
The Strict Alternation theory predicts that subjects will deterministically alternate their choices on every single trial, yielding an alternation rate of exactly 1.0 with zero variance. The Spatial Bias (Response Heuristic) theory, however, models choices probabilistically based on a bias and a sequential dependence. Even with the strongest tendency to alternate (beta_repeat = -3.0), the logistic function bounds the maximum alternation probability at approximately 0.95, and the presence of beta_bias can further reduce this. Therefore, measuring the trial-to-trial alternation rate will perfectly discriminate the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    shifted_resp = data.groupby('subject_id')['response'].shift(1)
    valid = shifted_resp.notna()
    if valid.sum() == 0:
        return 0.0
    return float((data.loc[valid, 'response'] != shifted_resp[valid]).mean())

### RESULTS
- Predicted under pi_6 (simulated): 1.0000 (var=0.0000)
- Predicted under pi_5 (simulated): 0.2818 (var=0.0562)
- Observed on real data: 1.0000 (var=0.0000)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=4):** [0.9, 0.8, 0.7, 0.6]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  trial 3: A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  trial 4: A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  trial 5: A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  trial 6: A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  trial 7: A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  trial 8: A=[0, 1, 1, 0]  B=[1, 0, 0, 1]

**Rationale:** Both the Spatial Bias (advocated) and Strict Alternation (competing) theories assume that subjects completely ignore the stimulus features and rely entirely on response heuristics. The key difference is that Strict Alternation predicts a deterministic, rigid alternation sequence with exactly zero overall spatial bias (50% A, 50% B), whereas the Spatial Bias model accommodates a probabilistic combination of spatial preference (e.g., favoring Option A) and sequential dependence (either repeating or alternating). To ensure that any observed spatial bias or repetition tendency is purely response-driven and not an artifact of the stimuli, we use a perfectly symmetric and counterbalanced set of trial pairs. Every feature configuration presented for Option A is also presented identically for Option B across the experiment. This guarantees that any feature-based strategy would result in a 50/50 overall choice rate and zero sequential dependence, allowing us to unambiguously dissociate the probabilistic spatial and repetition biases of the advocated theory from the rigid deterministic alternation of the competing theory.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
The Competing Theory predicts that subjects will strictly alternate their choices between Option A and Option B on every single trial. Therefore, the alternation rate (the proportion of trials where the current choice differs from the previous choice) will be exactly 1.0 for all subjects under this theory. In contrast, the Advocated Theory posits a probabilistic combination of spatial bias and sequential dependence, resulting in alternation rates that vary widely across subjects based on their individual parameters (typically averaging around 0.5). Measuring the mean alternation rate will unambiguously separate the rigid deterministic behavior of the Competing Theory from the flexible probabilistic behavior of the Advocated Theory.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    def subj_alt(df):
        resp = df['response'].values
        if len(resp) < 2:
            return 0.0
        return np.mean(resp[1:] != resp[:-1])
    return data.groupby('subject_id').apply(subj_alt).mean()

### RESULTS
- Predicted under pi_6 (simulated): 1.0000 (var=0.0000)
- Predicted under pi_5 (simulated): 0.3177 (var=0.0791)
- Observed on real data: 1.0000 (var=0.0000)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_pred = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred is not None:
            matches.append(1 if resp == ttb_pred else 0)
            
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_6:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5062 (var=0.0069)

### Experiment 4
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    # Determine which option is favored by the highest validity cue (cue 0)
    cue_0_a = a_ratings[:, 0]
    cue_0_b = b_ratings[:, 0]
    cue_0_winner = (cue_0_b > cue_0_a).astype(int)
    
    # Did the subject choose the option favored by cue 0?
    chose_cue_0 = (data['response'] == cue_0_winner).astype(float)
    
    # Calculate the tally difference in favor of the cue 0 winner
    tally_a = (a_ratings > b_ratings).sum(axis=1)
    tally_b = (b_ratings > a_ratings).sum(axis=1)
    tally_diff = np.where(cue_0_winner == 0, tally_a - tally_b, tally_b - tally_a)
    
    # Compare choice probabilities when tally strongly agrees vs. disagrees/ties with cue 0
    high_diff_mask = tally_diff >= 3
    low_diff_mask = tally_diff <= 0
    
    if not np.any(high_diff_mask) or not np.any(low_diff_mask):
        return 0.0
        
    high_diff_rate = chose_cue_0[high_diff_mask].mean()
    low_diff_rate = chose_cue_0[low_diff_mask].mean()
    
    return float(high_diff_rate - low_diff_rate)

```

**Observed (real) value:** -0.0237 (var=0.0386)
**Predicted under pi_6:** -0.0237 (var=0.0386)
**Predicted under pi_5:** 0.0115 (var=0.0099)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    subject_mins = []
    for subj, subj_df in data.groupby('subject_id'):
        pair_adherence = {}
        for _, row in subj_df.iterrows():
            a = tuple(row['option_a_ratings'])
            b = tuple(row['option_b_ratings'])
            # Use frozenset to group identical trial pairs regardless of A/B presentation order
            pair_key = frozenset({a, b})
            
            # Determine Take The Best (TTB) prediction
            ttb_choice = None
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_choice = 0
                    break
                elif b[i] > a[i]:
                    ttb_choice = 1
                    break
            
            if ttb_choice is None:
                continue
                
            adherence = 1 if row['response'] == ttb_choice else 0
            
            if pair_key not in pair_adherence:
                pair_adherence[pair_key] = []
            pair_adherence[pair_key].append(adherence)
            
        if not pair_adherence:
            continue
            
        # Compute the proportion of TTB adherence for each unique trial pair
        proportions = [sum(advs)/len(advs) for advs in pair_adherence.values()]
        # Take the minimum adherence across all pairs for this subject
        subject_mins.append(min(proportions))
        
    if not subject_mins:
        return 0.0
        
    # Return the average of these minimums across all subjects
    return float(sum(subject_mins) / len(subject_mins))
```

**Observed (real) value:** 0.2667 (var=0.0067)
**Predicted under pi_6:** 0.2767 (var=0.0062)
**Predicted under pi_5:** 0.2617 (var=0.0331)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    return float((data['response'] == 0).mean())
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_6:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5144 (var=0.0946)

### Experiment 7
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where Option B dominates on the top 3 most valid features (Trials 7 & 8)
    b_top3 = data['option_b_ratings'].apply(lambda x: x[0] == 1 and x[1] == 1 and x[2] == 1)
    
    # Identify trials where Option A dominates on the top 3 most valid features (Trials 1 & 2)
    a_top3 = data['option_a_ratings'].apply(lambda x: x[0] == 1 and x[1] == 1 and x[2] == 1)
    
    chose_b = (data['response'] == 1).astype(float)
    
    # Difference in probability of choosing B when B has the best features vs when A has them
    mean_b_when_b_best = chose_b[b_top3].mean()
    mean_b_when_a_best = chose_b[a_top3].mean()
    
    # Fallback to 0.0 if for some reason a subject is missing these trials
    if pd.isna(mean_b_when_b_best) or pd.isna(mean_b_when_a_best):
        return 0.0
        
    return float(mean_b_when_b_best - mean_b_when_a_best)
```

**Observed (real) value:** 0.0700 (var=0.0576)
**Predicted under pi_6:** 0.0600 (var=0.0589)
**Predicted under pi_5:** 0.0208 (var=0.0131)

### Experiment 8
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    correct = 0
    total = 0
    for _, row in data.iterrows():
        sum_a = sum(row['option_a_ratings'])
        sum_b = sum(row['option_b_ratings'])
        if sum_a == 5 and sum_b == 0:
            if row['response'] == 0:
                correct += 1
            total += 1
        elif sum_a == 0 and sum_b == 5:
            if row['response'] == 1:
                correct += 1
            total += 1
    return float(correct / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_6:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5100 (var=0.0091)

### Experiment 9
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[0, 0, 0, 1]  B=[1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    def subject_score(df):
        responses = df['response'].values
        if len(responses) == 0:
            return 0.0
        p_A = np.mean(responses == 0)
        if len(responses) > 1:
            p_repeat = np.mean(responses[1:] == responses[:-1])
        else:
            p_repeat = 0.5
        return float(abs(p_A - 0.5) + abs(p_repeat - 0.5))
    return float(data.groupby('subject_id').apply(subject_score).mean())
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_6:** 0.5000 (var=0.0000)
**Predicted under pi_5:** 0.5771 (var=0.0766)

### Experiment 10
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    def subject_score(df):
        resp = df['response'].values
        if len(resp) < 2:
            return 0.5
        p_A = float((resp == 0).mean())
        p_B = float((resp == 1).mean())
        p_rep = float((resp[1:] == resp[:-1]).mean())
        p_alt = float((resp[1:] != resp[:-1]).mean())
        return max(p_A, p_B, p_rep, p_alt)
        
    return float(data.groupby('subject_id').apply(subject_score).mean())
```

**Observed (real) value:** 1.0000 (var=0.0000)
**Predicted under pi_6:** 1.0000 (var=0.0000)
**Predicted under pi_5:** 0.8418 (var=0.0109)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Theory 1 (Strict Alternation) is remarkably accurate, perfectly predicting the deterministic alternation rate of 1.0 observed in Experiments 1 and 2, as well as matching the observed metrics across all other experiments. Theory 2 (Spatial Bias) fails significantly because its probabilistic formulation and inclusion of spatial bias inherently prevent it from capturing the rigid, deterministic alternation behavior exhibited by the subjects. Since Theory 1 perfectly explains the data, Theory 2 is fundamentally degenerate in this domain.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace Theory 2 with a brand-new theory that can serve as a strong conceptual competitor to Strict Alternation while still matching the deterministic data. For example, propose a 'Global Choice Balancing' theory: instead of local motor alternation, subjects maintain a running tally of how many times they have chosen Option A versus Option B across the entire experiment. On each trial, they deterministically choose the option with the lower tally (breaking ties randomly, e.g., on the first trial). This would produce the exact same sequence of alternating choices as Theory 1 but posits a global frequency-matching cognitive mechanism rather than a local trial-to-trial motor shift."
}
```

## Usage

```json
{
  "prompt_token_count": 8372,
  "candidates_token_count": 268,
  "total_token_count": 9632
}
```
