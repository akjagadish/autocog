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
Take The Best (TTB): People compare two options by ordering features by their subjective validity and searching through them sequentially. The search stops at the first feature that discriminates between the two options (i.e., one option has a higher value than the other), and the decision is based entirely on that single feature. This non-compensatory strategy ignores all other features, preventing any compensatory trade-offs. If no feature discriminates, the learner guesses. Response noise is modeled via an independent lapse rate epsilon, which replaces the deterministic TTB choice with a uniform random pick.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")

    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Order features by validity in descending order
    order = np.argsort(validities, kind='stable')[::-1]
    
    # Default to guessing if no cue discriminates
    p_core = np.array([0.5, 0.5])
    
    # Sequential search for the first discriminating cue
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    n_opts = p_core.shape[0]
    
    # Blend deterministic choice with uniform lapse
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_5
Strategy Mixture: Decision-makers predominantly use a deterministic non-compensatory heuristic (Take-The-Best) but probabilistically substitute it with a simple compensatory heuristic (Tallying) on a trial-by-trial basis. This mixture captures the overwhelming adherence to TTB while accounting for systematic deviations toward options with a higher quantity of positive cues in extreme conflict scenarios.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Strategy Mixture expects a (2, n_features) stimulus.")

    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    p_ttb = float(parameters["p_ttb"])
    epsilon = float(parameters["epsilon"])
    
    # Take-The-Best (TTB) Strategy
    order = np.argsort(validities, kind='stable')[::-1]
    p_ttb_choice = np.array([0.5, 0.5])
    for idx in order:
        if a[idx] > b[idx]:
            p_ttb_choice = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_ttb_choice = np.array([0.0, 1.0])
            break
            
    # Tallying Strategy (Equal Weights)
    sum_a = np.sum(a)
    sum_b = np.sum(b)
    if sum_a > sum_b:
        p_tally_choice = np.array([1.0, 0.0])
    elif sum_b > sum_a:
        p_tally_choice = np.array([0.0, 1.0])
    else:
        p_tally_choice = np.array([0.5, 0.5])
        
    # Mixture of the two strategies
    p_core = p_ttb * p_ttb_choice + (1.0 - p_ttb) * p_tally_choice
    
    # Uniform lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 5: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 7: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 8: A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]

**Rationale:** To maximally distinguish pure Take The Best (Theory 1) from a Strategy Mixture of Take The Best and Tallying (Theory 2), we must create trials where the two underlying heuristics (TTB and Tallying) make conflicting predictions. TTB always chooses the option favored by the single highest-validity discriminating feature. Tallying chooses the option with the greatest total number of positive features, ignoring their validities. We design 'conflict' trials where Option A is favored by the highest-validity discriminating cue (so TTB chooses A), but Option B has a strictly greater number of positive cues overall (so Tallying chooses B). Theory 1 will consistently choose Option A on these trials (subject only to uniform lapse), whereas Theory 2 will show a systematically lower probability of choosing Option A because it probabilistically substitutes the Tallying strategy. We also include agreement trials and tie trials (where Tallying predicts a tie) to baseline the lapse rates and isolate the mixture parameter.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
The metric computes the proportion of choices that align with the Tallying heuristic specifically on 'conflict trials' - trials where Take-The-Best (TTB) and Tallying predict different options. For the pure TTB theory, choices aligning with Tallying on these trials can only occur due to random lapses, keeping the metric near 0. For the Strategy Mixture theory, the metric will be significantly higher because subjects probabilistically substitute TTB with Tallying, causing systematic deviations toward the Tallying-favored option.

Source:
def metric(data: pd.DataFrame) -> float:
    tally_choices = 0
    conflict_trials = 0
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        # TTB preference (features are ordered by validity 0 to 4)
        ttb_pref = -1
        for i in range(5):
            if a[i] > b[i]:
                ttb_pref = 0
                break
            elif b[i] > a[i]:
                ttb_pref = 1
                break
                
        # Tallying preference
        sum_a = sum(a)
        sum_b = sum(b)
        if sum_a > sum_b:
            tally_pref = 0
        elif sum_b > sum_a:
            tally_pref = 1
        else:
            tally_pref = -1
            
        # Check if it's a conflict trial
        if ttb_pref != -1 and tally_pref != -1 and ttb_pref != tally_pref:
            conflict_trials += 1
            if resp == tally_pref:
                tally_choices += 1
                
    if conflict_trials == 0:
        return 0.0
    return tally_choices / conflict_trials

### RESULTS
- Predicted under pi_3 (simulated): 0.1240 (var=0.0073)
- Predicted under pi_5 (simulated): 0.2033 (var=0.0124)
- Observed on real data: 0.1573 (var=0.0161)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 5: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 6: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1]
  trial 7: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 8: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 9: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  trial 10: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Rationale:** To maximally distinguish Theory 1 (Strategy Mixture: TTB + Tallying) from Theory 2 (pure TTB), we design trials that create a strong conflict between the Take-The-Best (TTB) and Tallying heuristics. TTB relies solely on the single highest-validity discriminating feature, while Tallying relies entirely on the unweighted sum of positive features. By creating 'conflict' trials where Option A is favored by the highest-validity discriminating feature but Option B has a strictly greater total number of positive features, pure TTB will consistently choose Option A, whereas the Strategy Mixture model will probabilistically choose Option B on a fraction of trials. We also include 'agreement' trials (where both heuristics favor the same option) and 'Tallying tie' trials (where Tallying is indifferent but TTB strongly prefers one option) to independently estimate lapse rates and the mixing parameter.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
This metric calculates the difference in the rate of choosing Option B between 'conflict' trials (where TTB favors A but Tallying favors B) and 'agreement' trials (where both TTB and Tallying favor A). Under pure TTB, Option B is only chosen due to random lapses (epsilon/2) in both trial types, so the expected difference is 0. Under the Strategy Mixture model, Option B is chosen more frequently on conflict trials because of the probabilistic use of Tallying, resulting in a strictly positive difference. By subtracting the agreement baseline, this metric cleanly isolates the Tallying component while canceling out individual differences in lapse rates.

Source:
def metric(data: pd.DataFrame) -> float:
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    conflict_mask = sum_b > sum_a
    agreement_mask = sum_a > sum_b
    
    if conflict_mask.sum() == 0 or agreement_mask.sum() == 0:
        return 0.0
        
    p_b_conflict = data.loc[conflict_mask, 'response'].mean()
    p_b_agreement = data.loc[agreement_mask, 'response'].mean()
    
    return float(p_b_conflict - p_b_agreement)

### RESULTS
- Predicted under pi_3 (simulated): -0.0003 (var=0.0180)
- Predicted under pi_5 (simulated): 0.1657 (var=0.0232)
- Observed on real data: 0.0152 (var=0.0118)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    # Create a safe, hashable string identifier for each trial type
    data['trial_id'] = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x])) + '_' + \
                       data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    # Calculate the Tallying difference (wins for A - wins for B)
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    data['tally_diff'] = np.sum(a_ratings > b_ratings, axis=1) - np.sum(b_ratings > a_ratings, axis=1)
    
    # Calculate choice for A (response == 0 means A was chosen)
    data['choice_A'] = 1 - data['response']
    
    # Calculate the proportion of times A was chosen for each trial type, per subject
    trial_means = data.groupby(['subject_id', 'tally_diff', 'trial_id'])['choice_A'].mean().reset_index()
    
    # Compute the pooled within-group variance of choice proportions for each subject
    def pooled_variance(df):
        var_sum = 0.0
        df_sum = 0.0
        for t_diff, group in df.groupby('tally_diff'):
            n = len(group)
            if n > 1:
                v = group['choice_A'].var(ddof=1)
                var_sum += v * (n - 1)
                df_sum += (n - 1)
        if df_sum == 0:
            return 0.0
        return float(var_sum / df_sum)
        
    subj_vars = []
    for subj, subj_df in trial_means.groupby('subject_id'):
        subj_vars.append(pooled_variance(subj_df))
        
    return float(np.mean(subj_vars))
```

**Observed (real) value:** 0.1080 (var=0.0018)
**Predicted under pi_3:** 0.1180 (var=0.0015)
**Predicted under pi_5:** 0.1177 (var=0.0011)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def is_fewer_but_better(a, b):
        return tuple(a) == (1, 1, 0, 0, 0) and tuple(b) == (0, 0, 1, 1, 1)
        
    def is_worse_but_more(a, b):
        return tuple(a) == (0, 0, 1, 1, 1) and tuple(b) == (1, 1, 0, 0, 0)

    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        if is_fewer_but_better(a, b):
            matches.append(1.0 if resp == 0 else 0.0)
        elif is_worse_but_more(a, b):
            matches.append(1.0 if resp == 1 else 0.0)
            
    if not matches:
        return 0.5
    return float(np.mean(matches))
```

**Observed (real) value:** 0.8267 (var=0.0120)
**Predicted under pi_3:** 0.8667 (var=0.0122)
**Predicted under pi_5:** 0.7517 (var=0.0248)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    matches = 0
    total = 0
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        for f_a, f_b in zip(a, b):
            if f_a > f_b:
                if r == 0:
                    matches += 1
                total += 1
                break
            elif f_b > f_a:
                if r == 1:
                    matches += 1
                total += 1
                break
    return float(matches / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.8431 (var=0.0052)
**Predicted under pi_3:** 0.8836 (var=0.0052)
**Predicted under pi_5:** 0.7518 (var=0.0141)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    A = np.stack(data['option_a_ratings'].values)
    B = np.stack(data['option_b_ratings'].values)
    diff = A - B
    first_diff_idx = np.argmax(np.abs(diff), axis=1)
    first_diff_val = diff[np.arange(len(diff)), first_diff_idx]
    ttb_choice = np.where(first_diff_val == 1, 0, 1)
    return float(np.mean(data['response'].values == ttb_choice))
```

**Observed (real) value:** 0.8525 (var=0.0074)
**Predicted under pi_3:** 0.8923 (var=0.0049)
**Predicted under pi_5:** 0.7631 (var=0.0144)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_matches = 0
    total = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        response = row['response']
        
        ttb_choice = -1
        for i in range(5):
            if a[i] > b[i]:
                ttb_choice = 0
                break
            elif b[i] > a[i]:
                ttb_choice = 1
                break
                
        if ttb_choice == response:
            ttb_matches += 1
        total += 1
        
    return float(ttb_matches) / total if total > 0 else 0.0
```

**Observed (real) value:** 0.8446 (var=0.0117)
**Predicted under pi_3:** 0.8740 (var=0.0063)
**Predicted under pi_5:** 0.8535 (var=0.0047)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    deviations = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        # Determine the deterministic TTB choice (first discriminating cue)
        ttb_choice = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_choice = 0
                break
            elif b[i] > a[i]:
                ttb_choice = 1
                break
                
        if ttb_choice == -1:
            continue
            
        # Count how many cues favor each option
        cues_a = sum(1 for i in range(len(a)) if a[i] > b[i])
        cues_b = sum(1 for i in range(len(b)) if b[i] > a[i])
        
        # Isolate extreme conflict trials:
        # TTB choice is supported by EXACTLY 1 cue, 
        # while the opposing option is supported by >= 3 cues.
        if ttb_choice == 0 and cues_a == 1 and cues_b >= 3:
            deviations.append(1.0 if resp == 1 else 0.0)
        elif ttb_choice == 1 and cues_b == 1 and cues_a >= 3:
            deviations.append(1.0 if resp == 0 else 0.0)
            
    if not deviations:
        return 0.5
    return float(np.mean(deviations))
```

**Observed (real) value:** 0.1622 (var=0.0212)
**Predicted under pi_3:** 0.1322 (var=0.0117)
**Predicted under pi_5:** 0.2656 (var=0.0192)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (pure Take-The-Best) consistently outperforms Theory 2 (Strategy Mixture). In Experiment 2, the observed difference in Tallying-favored choices between conflict and agreement trials is nearly zero (0.0152), which aligns with the pure TTB prediction (-0.0003) and strongly contradicts the Strategy Mixture prediction (0.1657). Similarly, in Experiments 4, 5, 6, and 8, pure TTB provides much more accurate predictions of the observed metrics, while the Strategy Mixture significantly overpredicts the influence of the Tallying heuristic. Theory 2's assumption that subjects probabilistically substitute TTB with Tallying is not supported by the data, making it degenerate.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a new theory based on 'Subjective Take-The-Best' or 'Noisy Cue Ordering'. Instead of a mixture with Tallying, subjects might purely use TTB but with a subjective cue hierarchy that occasionally deviates from the objective validities (e.g., due to memory constraints or learning noise). Alternatively, propose a compensatory model with exponentially decaying weights (where feature weights are proportional to their validities), which mimics TTB in most cases but allows for soft compensatory behavior without explicitly invoking a separate Tallying strategy."
}
```

## Usage

```json
{
  "prompt_token_count": 8789,
  "candidates_token_count": 310,
  "total_token_count": 10016
}
```
