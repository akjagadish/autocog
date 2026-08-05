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


## THEORY 2 — pi_4
Stochastic Take-The-Best (STTB): People use a non-compensatory, one-reason heuristic to compare options, but their search order is probabilistic rather than strictly deterministic. The probability of examining a cue next is determined by a softmax over the subjective validities of the remaining unexamined cues. The search stops at the first feature that discriminates between the two options, and the decision is based solely on that feature. If the selected feature ties, it is ignored and the search continues. If all features are exhausted without a discriminator, the decision maker guesses. This model interpolates between strict Take-The-Best (at high inverse temperature) and the Minimalist heuristic with random cue search (at zero inverse temperature).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("STTB expects a (2, n_features) stimulus.")

    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    def get_prob(available_cues):
        if len(available_cues) == 0:
            return np.array([0.5, 0.5])
        
        v = validities[available_cues]
        z = beta * v
        z = z - np.max(z)  # numerical stability
        p = np.exp(z)
        p = p / np.sum(p)
        
        ans = np.zeros(2)
        for i, cue_idx in enumerate(available_cues):
            if a[cue_idx] > b[cue_idx]:
                ans[0] += p[i]
            elif b[cue_idx] > a[cue_idx]:
                ans[1] += p[i]
            else:
                new_cues = [c for c in available_cues if c != cue_idx]
                ans += p[i] * get_prob(new_cues)
        return ans

    n_features = len(validities)
    p_core = get_prob(list(range(n_features)))
    
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.92, 0.9, 0.88, 0.86, 0.84]

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 6: A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 9: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 10: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 11: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 12: A=[0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1]

**Rationale:** To maximally distinguish deterministic Take The Best (TTB) from Stochastic Take-The-Best (STTB), we need to exploit the difference between strict rank-based feature selection and probabilistic feature selection. By using a set of feature validities that are relatively close to one another, TTB will still rigidly select the single most valid discriminating feature every time. In contrast, STTB (unless the inverse temperature beta is extremely high) will frequently sample slightly less valid features first. We construct trials where the highest-validity discriminating feature strongly favors one option, but multiple slightly lower-validity features favor the other option. TTB will consistently choose the option favored by the top feature, whereas STTB will show a graded preference or even flip its choice depending on the number and validities of the opposing features.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of trials where the subject's choice matches the strictly deterministic Take-The-Best (TTB) prediction. Under the TTB theory, subjects will consistently choose the option favored by the single highest-validity discriminating feature (yielding a high match rate, only reduced by the lapse rate epsilon). Under Stochastic Take-The-Best (STTB), subjects probabilistically sample features based on their validities. Because the experimental design includes many trials where the highest-validity feature points to one option but multiple lower-validity features point to the other, STTB will frequently choose the non-TTB option, resulting in a significantly lower match rate.

Source:
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

### RESULTS
- Predicted under pi_3 (simulated): 0.8740 (var=0.0063)
- Predicted under pi_4 (simulated): 0.7423 (var=0.0155)
- Observed on real data: 0.8446 (var=0.0117)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.92, 0.89, 0.86, 0.83]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 4: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 7: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 9: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 10: A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]

**Rationale:** To maximally distinguish deterministic Take-The-Best (TTB) from Stochastic Take-The-Best (STTB), we use a set of validities that are relatively close to each other. TTB strictly relies on the single highest-validity discriminating feature, entirely ignoring the rest. STTB, however, samples features probabilistically based on their validities. By constructing trials where the single best feature favors one option (A) but multiple slightly lower-validity features favor the other option (B), TTB will deterministically choose A, while STTB will frequently sample one of the lower-validity features first and therefore choose B. Varying the number and validities of the opposing features provides a graded quantitative dissociation.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
This metric calculates the deviation rate from Take-The-Best (TTB) specifically on the most extreme conflict trials. In these trials, the highest-validity cue favors one option (the TTB choice), but almost all other cues (3 or 4) favor the opposing option. Deterministic TTB entirely ignores the sheer number of opposing cues and will only deviate due to random lapses, predicting a consistently low deviation rate. Stochastic TTB (STTB), however, samples cues probabilistically. Because there are many more cues favoring the opposing option, STTB has a high probability of sampling one of them before the single highest-validity cue, leading to a much higher deviation rate. By filtering out milder conflict trials, we maximize the expected mean gap between the theories.

Source:
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

### RESULTS
- Predicted under pi_3 (simulated): 0.1322 (var=0.0117)
- Predicted under pi_4 (simulated): 0.2556 (var=0.0393)
- Observed on real data: 0.1622 (var=0.0212)

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
**Predicted under pi_4:** 0.1255 (var=0.0017)

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
**Predicted under pi_4:** 0.8658 (var=0.0077)

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
**Predicted under pi_4:** 0.8327 (var=0.0236)

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
**Predicted under pi_4:** 0.7837 (var=0.0262)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (Deterministic Take-The-Best, pi_3) significantly outperforms Theory 2 (Stochastic TTB, pi_4). The observed data shows a very high adherence to the deterministic TTB choices (e.g., ~84-85% match rate in Exps 1, 5, 6), which pi_3 predicts well (though it slightly overestimates at ~87-89%). In extreme conflict trials (Exp 2), the observed deviation from TTB is 0.1622, which is close to pi_3's prediction of 0.1322 and far lower than pi_4's 0.2556. This indicates that feature search is largely deterministic and rank-ordered, not probabilistically sampled via softmax. However, pi_3 consistently under-predicts the slight pull of compensatory features (as seen by the small gap between observed and pi_3 predictions). Theory 2 is degenerate because its core assumption of probabilistic cue search overestimates deviations from TTB. A better alternative would be a strategy mixture model.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Strategy Mixture' theory. Instead of a probabilistic search order (STTB), assume that decision-makers are heterogeneous or trial-by-trial probabilistically choose between two distinct strategies: deterministic Take-The-Best (TTB) and a simple compensatory strategy like Tallying (choosing the option with the highest total number of positive cues, regardless of validity). This mixture model will capture the overwhelmingly TTB-like behavior in the aggregate data, while perfectly explaining the small, systematic deviations toward options with a sheer higher quantity of cues (as seen in Experiment 2's extreme conflict trials)."
}
```

## Usage

```json
{
  "prompt_token_count": 7448,
  "candidates_token_count": 397,
  "total_token_count": 8938
}
```
