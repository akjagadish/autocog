# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_5" and "pi_2_1") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_5" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2_1" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_5
People make decisions by computing a weighted sum of feature differences, where the weights are proportional to the log-odds of the cue validities. A parameter gamma interpolates between equal weighting (Tallying, gamma=0) and full log-odds weighting (gamma=1). This Compensatory Weighted Additive (WADD) strategy allows multiple lower-validity cues to outweigh a single high-validity cue, while capturing slight validity-driven effects that pure Tallying misses. Response noise is modeled via a softmax function and an independent lapse rate.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Calculate log-odds of validities
    clipped_val = np.clip(val, 0.5001, 0.9999)
    log_odds = np.log(clipped_val / (1.0 - clipped_val))
    
    # Apply gamma to scale the log-odds (gamma=0 -> equal weights/Tallying)
    weights = np.maximum(log_odds, 1e-9) ** gamma
    
    # Compute weighted sum of feature differences (strict wins)
    a_wins = np.sum((a > b) * weights)
    b_wins = np.sum((b > a) * weights)
    scores = np.array([a_wins, b_wins])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_2_1
People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    # Paper-faithful Tallying heuristic (Dawes 1979; Gigerenzer &
    # Goldstein 1999). Stimulus is the pair of option feature vectors
    # for the current trial: array-like of shape (2, n_features),
    # with row 0 = option A, row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    # Count strict feature-wise wins; ties contribute to neither option.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. When
    # a_wins == b_wins the softmax is exactly uniform regardless of
    # beta, which is the correct behavior for an undiscriminating
    # tally.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_5)

### DESIGN
**Validities (n_features=7):** [0.96, 0.91, 0.82, 0.73, 0.64, 0.58, 0.53]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 0]
  trial 2: A=[0, 0, 1, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0, 0]
  trial 3: A=[1, 0, 1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 0, 1, 1, 0, 0]  B=[1, 0, 1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0]
  trial 6: A=[0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0]
  trial 7: A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1]
  trial 8: A=[0, 1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0, 1]

**Rationale:** This design utilizes 7 features with a wide and non-linear spread of validities to definitively separate the unweighted counting mechanism of Tallying from the log-odds validity weighting of WADD. Tallying ignores validity entirely, counting only the number of features favoring each option. WADD evaluates the weighted sum of feature differences. By including trials where one option wins on a small number of highly valid features while the other wins on a larger number of low-validity features, the models predict choices in opposite directions. Furthermore, 'tie' trials for Tallying (where both options win on an equal number of features) will yield 50/50 guessing under Tallying but deterministic, validity-driven preferences under WADD. This 7-feature structure avoids the already-explored 5- and 6-feature paradigms while providing maximum quantitative divergence.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the expected value of the product between the subject's choice (+1 for A, -1 for B) and the WADD log-odds score difference for the trial. Because the experimental design deliberately structures 'reversal' trials such that the simple feature count (Tallying) reliably points in the opposite direction of the log-odds weighted sum (WADD), the two theories produce expected scores with opposite signs. For a subject utilizing Tallying, their choices will systematically anti-correlate with the WADD score differences across the experiment, yielding a strictly negative metric value. For a subject utilizing WADD, their choices will positively align with the WADD score differences, yielding a strictly positive metric value. By averaging this continuous measure over all 96 trials, binomial noise is heavily suppressed, ensuring a large mean gap and tight per-subject variance.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Log-odds of the validities used in the experimental design
    val = np.array([0.96, 0.91, 0.82, 0.73, 0.64, 0.58, 0.53])
    log_odds = np.log(val / (1.0 - val))
    
    subject_scores = []
    for subj, subj_df in data.groupby('subject_id'):
        score = 0.0
        for _, row in subj_df.iterrows():
            a = np.array(row['option_a_ratings'])
            b = np.array(row['option_b_ratings'])
            
            # Compute the WADD score difference for this trial
            wadd_diff = float(np.sum((a > b) * log_odds) - np.sum((b > a) * log_odds))
            
            # Represent choice as +1 for Option A, -1 for Option B
            choice_sign = 1.0 if row['response'] == 0 else -1.0
            
            # Multiply choice sign by the WADD score difference
            score += choice_sign * wadd_diff
            
        # Average score per trial for this subject
        subject_scores.append(score / len(subj_df))
        
    return float(np.mean(subject_scores))

### RESULTS
- Predicted under pi_5 (simulated): 0.1936 (var=0.1402)
- Predicted under pi_2_1 (simulated): -0.1052 (var=0.0731)
- Observed on real data: 0.0247 (var=0.1180)

## EXPERIMENT 2 (proposed by pi_2_1)

### DESIGN
**Validities (n_features=4):** [0.98, 0.6, 0.55, 0.51]

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  trial 3: A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  trial 4: A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  trial 5: A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  trial 6: A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  trial 7: A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  trial 8: A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  trial 9: A=[0, 1, 1, 0]  B=[0, 0, 0, 1]
  trial 10: A=[1, 0, 0, 0]  B=[0, 0, 1, 0]
  trial 11: A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  trial 12: A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Rationale:** This design uses a 4-feature space with a highly skewed validity distribution to sharply dissociate the unweighted counting mechanism of Tallying from the log-odds validity weighting of WADD. The validities are set such that the most valid cue heavily outweighs the combined log-odds of all other cues. We include 'conflict' trials where one option wins on the single most valid cue but loses on all three remaining cues, causing Tallying to strongly prefer one option (3 wins vs 1 win) while WADD predicts the exact opposite choice. Additionally, we include multiple 'tie' trials where both options win on an equal number of cues (e.g., 2 vs 2). For these, Tallying predicts a 50/50 guess, while WADD makes deterministic predictions driven by the validity weights. This minimal 4-feature design provides a robust, quantitative divergence between the models without the complexity of higher-dimensional feature spaces.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of choices that align with the most valid cue (cue 1) on trials where the options differ on this cue. In this specific experimental design, the first cue is highly predictive (0.98 validity), but whenever it differentiates the options, the remaining cues either exactly tie or collectively oppose it. Under the Compensatory WADD model, the extreme log-odds of the first cue dominate the decision, leading to a high alignment proportion. Under the Tallying model, cues are unweighted; thus, the subject will either guess (when the total number of winning cues is tied) or actively choose the option that loses on cue 1 (when it is outnumbered by the other three cues). Consequently, Tallying predicts an alignment proportion strictly less than or equal to 0.5, while WADD predicts a proportion significantly greater than 0.5.

Source:
def metric(data: pd.DataFrame) -> float:
    # Extract the first cue (the highly valid cue) for both options
    a_cue0 = data['option_a_ratings'].apply(lambda x: x[0])
    b_cue0 = data['option_b_ratings'].apply(lambda x: x[0])
    
    # Filter to trials where the two options differ on the first cue
    mask = a_cue0 != b_cue0
    if mask.sum() == 0:
        return 0.5
        
    # Check if the subject's response aligns with the first cue
    # (i.e., they chose the option that has a 1 for the first cue)
    aligned = ((a_cue0 == 1) & (data['response'] == 0)) | ((b_cue0 == 1) & (data['response'] == 1))
    
    return float(aligned[mask].mean())

### RESULTS
- Predicted under pi_5 (simulated): 0.5592 (var=0.0062)
- Predicted under pi_2_1 (simulated): 0.4850 (var=0.0056)
- Observed on real data: 0.5383 (var=0.0055)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
import pandas as pd
import numpy as np

def metric(data: pd.DataFrame) -> float:
    def ttb_choice(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]:
                return 0
            elif b[i] > a[i]:
                return 1
        return 0.5
    
    ttb_preds = data.apply(ttb_choice, axis=1)
    return float(np.mean(data['response'] == ttb_preds))
```

**Observed (real) value:** 0.4425 (var=0.0035)
**Predicted under pi_5:** 0.4752 (var=0.0042)
**Predicted under pi_2_1:** 0.4529 (var=0.0047)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_aligned_choices = 0
    disagreement_trials = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        tally_a = np.sum(a > b)
        tally_b = np.sum(b > a)
        
        if tally_a > tally_b:
            tally_pred = 0
        elif tally_b > tally_a:
            tally_pred = 1
        else:
            tally_pred = None
            
        ttb_pred = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
                
        if tally_pred is not None and ttb_pred is not None and tally_pred != ttb_pred:
            disagreement_trials += 1
            if row['response'] == ttb_pred:
                ttb_aligned_choices += 1
                
    if disagreement_trials == 0:
        return 0.5
        
    return float(ttb_aligned_choices / disagreement_trials)
```

**Observed (real) value:** 0.4578 (var=0.0041)
**Predicted under pi_5:** 0.4972 (var=0.0046)
**Predicted under pi_2_1:** 0.4439 (var=0.0058)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    opt1 = (1, 1, 0, 0, 0)
    opt2 = (0, 0, 1, 1, 0)
    
    chose_opt1 = []
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        if a == opt1 and b == opt2:
            chose_opt1.append(1 if row['response'] == 0 else 0)
        elif a == opt2 and b == opt1:
            chose_opt1.append(1 if row['response'] == 1 else 0)
            
    if not chose_opt1:
        return 0.5
    return sum(chose_opt1) / len(chose_opt1)
```

**Observed (real) value:** 0.5100 (var=0.0385)
**Predicted under pi_5:** 0.5433 (var=0.0270)
**Predicted under pi_2_1:** 0.4667 (var=0.0156)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1_mask = data['A_str'] == '11000'
    t4_mask = data['A_str'] == '00011'
    
    # response == 0 means subject chose A
    p_A_t1 = 1.0 - data.loc[t1_mask, 'response'].mean()
    p_A_t4 = 1.0 - data.loc[t4_mask, 'response'].mean()
    
    if pd.isna(p_A_t1): p_A_t1 = 0.5
    if pd.isna(p_A_t4): p_A_t4 = 0.5
    
    return float(p_A_t1 - p_A_t4)
```

**Observed (real) value:** 0.0025 (var=0.0611)
**Predicted under pi_5:** 0.1400 (var=0.0354)
**Predicted under pi_2_1:** 0.0075 (var=0.0281)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Project lists to strings for hashable matching
    a_str = data['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    
    # Trial 1: A=[1,0,0,0,0], B=[0,1,1,1,0]. Tallying tally diff = 3 - 1 = 2.
    t1_mask = (a_str == "10000") & (b_str == "01110")
    # Trial 2: A=[1,0,0,0,0], B=[0,0,1,1,1]. Tallying tally diff = 3 - 1 = 2.
    t2_mask = (a_str == "10000") & (b_str == "00111")
    
    # Trial 7: A=[1,0,1,0,0], B=[0,1,0,1,1]. Tallying tally diff = 3 - 2 = 1.
    t7_mask = (a_str == "10100") & (b_str == "01011")
    # Trial 8: A=[1,1,0,0,0], B=[0,0,1,1,1]. Tallying tally diff = 3 - 2 = 1.
    t8_mask = (a_str == "11000") & (b_str == "00111")
    
    p_b_t1 = data.loc[t1_mask, 'response'].mean()
    p_b_t2 = data.loc[t2_mask, 'response'].mean()
    p_b_t7 = data.loc[t7_mask, 'response'].mean()
    p_b_t8 = data.loc[t8_mask, 'response'].mean()
    
    # Handle missing trial types gracefully
    p_b_t1 = 0.5 if pd.isna(p_b_t1) else p_b_t1
    p_b_t2 = 0.5 if pd.isna(p_b_t2) else p_b_t2
    p_b_t7 = 0.5 if pd.isna(p_b_t7) else p_b_t7
    p_b_t8 = 0.5 if pd.isna(p_b_t8) else p_b_t8
    
    # Tallying predicts exactly 0 difference for both pairs. 
    # WADD predicts positive differences because B has higher validity features in T1 vs T2, and T7 vs T8.
    return float((p_b_t1 - p_b_t2) + (p_b_t7 - p_b_t8))
```

**Observed (real) value:** -0.0700 (var=0.1048)
**Predicted under pi_5:** 0.0050 (var=0.0637)
**Predicted under pi_2_1:** -0.0417 (var=0.0484)

### Experiment 8
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np

    # Identify Trial 1: A=[1, 1, 0, 0, 0, 0], B=[0, 0, 0, 1, 1, 0]
    t1_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0, 0)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 0, 1, 1, 0))
    
    # Identify Trial 4: A=[0, 0, 0, 1, 1, 1], B=[1, 1, 1, 0, 0, 0]
    t4_mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 0, 1, 1, 1)) & \
              data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 1, 0, 0, 0))
    
    p_a_t1 = (data.loc[t1_mask, 'response'] == 0).mean()
    p_a_t4 = (data.loc[t4_mask, 'response'] == 0).mean()
    
    # Handle edge cases where a subject might have missed these trials (should not happen in full design)
    if pd.isna(p_a_t1): p_a_t1 = 0.5
    if pd.isna(p_a_t4): p_a_t4 = 0.5
    
    return float(p_a_t1 - p_a_t4)

```

**Observed (real) value:** 0.0800 (var=0.0525)
**Predicted under pi_5:** 0.1617 (var=0.0737)
**Predicted under pi_2_1:** -0.0100 (var=0.0405)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    ttb_agreements = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        
        # TTB prediction
        ttb_choice = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_choice = 0
                break
            elif b[i] > a[i]:
                ttb_choice = 1
                break
                
        # Tallying prediction
        tally_a = sum(1 for i in range(len(a)) if a[i] > b[i])
        tally_b = sum(1 for i in range(len(a)) if b[i] > a[i])
        
        if tally_a > tally_b:
            tally_choice = 0
        elif tally_b > tally_a:
            tally_choice = 1
        else:
            tally_choice = None
            
        # Only consider trials where the two heuristics make STRICTLY OPPOSITE predictions
        if ttb_choice is not None and tally_choice is not None and ttb_choice != tally_choice:
            ttb_agreements.append(row['response'] == ttb_choice)
            
    if not ttb_agreements:
        return 0.5
    return float(np.mean(ttb_agreements))
```

**Observed (real) value:** 0.4508 (var=0.0076)
**Predicted under pi_5:** 0.4792 (var=0.0053)
**Predicted under pi_2_1:** 0.4233 (var=0.0050)

### Experiment 10
**Design**
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.vstack(data['option_a_ratings'].values)
    b_ratings = np.vstack(data['option_b_ratings'].values)
    
    a_wins = np.sum(a_ratings > b_ratings, axis=1)
    b_wins = np.sum(b_ratings > a_ratings, axis=1)
    
    tally_pred = np.where(a_wins > b_wins, 0, np.where(b_wins > a_wins, 1, -1))
    
    diff = a_ratings - b_ratings
    first_diff_idx = np.argmax(diff != 0, axis=1)
    ttb_pred = np.where(diff[np.arange(len(diff)), first_diff_idx] > 0, 0, 1)
    
    diagnostic = (tally_pred != -1) & (tally_pred != ttb_pred)
    
    if not np.any(diagnostic):
        return 0.5
        
    responses = data['response'].values[diagnostic]
    tally_preds = tally_pred[diagnostic]
    
    return float(np.mean(responses == tally_preds))
```

**Observed (real) value:** 0.5725 (var=0.0079)
**Predicted under pi_5:** 0.5312 (var=0.0057)
**Predicted under pi_2_1:** 0.5667 (var=0.0084)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the 10 experiments, the observed data consistently falls between the predictions of the Compensatory WADD model (THEORY 1) and the pure Tallying model (THEORY 2). In experiments with extreme cue validities (like Exp 2), subjects show a clear sensitivity to the most valid cue, which Tallying completely misses. Conversely, in experiments with more distributed validities, subjects behave much more like unweighted tallyers, making WADD overpredict the influence of lower-validity cues (as seen in Exp 6, 7, and 10). Neither a purely unweighted approach nor a purely compensatory log-odds approach fully captures the nuance of human choices, suggesting that subjects might be employing a mixture of heuristics depending on the choice environment, or a probabilistic choice between Take-The-Best (TTB) and Tallying.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Strategy Mixture' theory that replaces pure Tallying. This new theory should posit that subjects probabilistically choose between two distinct heuristics on a trial-by-trial basis: Take-The-Best (which relies solely on the most valid discriminating cue) and Tallying (which counts total feature wins). This mixture model can naturally capture both the strong influence of highly valid cues in some trials (via TTB) and the general unweighted integration in others (via Tallying), providing a much better fit for the intermediate values observed across the experiments."
}
```

## Usage

```json
{
  "prompt_token_count": 10438,
  "candidates_token_count": 332,
  "total_token_count": 11897
}
```
