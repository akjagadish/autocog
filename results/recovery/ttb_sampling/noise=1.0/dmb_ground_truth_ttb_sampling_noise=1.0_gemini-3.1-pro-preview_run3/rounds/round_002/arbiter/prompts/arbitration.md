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
Take-The-Best (TTB) heuristic with subjective validity noise: Decision-makers search through features in descending order of their subjective validity, but their assessment of validity is noisy. On any given evaluation, they sample validities with some variance, sort features by these sampled validities, and stop at the first feature that discriminates between the two options. Response noise is modeled via a softmax over the resulting binary preference scores, plus an independent lapse rate. Averaging over multiple samples naturally smooths the aggregate predictions when validities are close.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("TTB expects a (2, n_features) stimulus.")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    sigma = float(parameters["sigma"])
    
    n_samples = 50
    avg_p_core = np.zeros(2)
    
    for _ in range(n_samples):
        noisy_v = validities + np.random.normal(0, sigma, size=validities.shape)
        order = np.argsort(noisy_v)[::-1]
        
        scores = np.zeros(2)
        # Search for the first discriminating feature
        for idx in order:
            if stim[0, idx] > stim[1, idx]:
                scores[0] = 1.0
                break
            elif stim[1, idx] > stim[0, idx]:
                scores[1] = 1.0
                break
                
        # Softmax over the scores
        z = beta * (scores - scores.max())
        e = np.exp(z)
        p_core = e / e.sum()
        avg_p_core += p_core
        
    avg_p_core /= n_samples
    
    n_opts = avg_p_core.shape[0]
    return (1.0 - epsilon) * avg_p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_4
Strategy Mixture: Decision-makers are heterogeneous and use a mixture of non-compensatory and compensatory heuristics. On any given trial, a decision is made either via Take-The-Best (relying solely on the most valid discriminating feature) or Tallying (counting the total number of winning features), governed by a mixing parameter. When these strategies conflict, their opposing choices average out across the population, naturally capturing the ~0.5 aggregate choice proportions observed across experiments without relying on massive uniform noise.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    p_ttb = float(parameters["p_ttb"])
    
    # Take-The-Best (TTB) predictions
    order = np.argsort(validities)[::-1]
    ttb_scores = np.zeros(2)
    for idx in order:
        if stim[0, idx] > stim[1, idx]:
            ttb_scores[0] = 1.0
            break
        elif stim[1, idx] > stim[0, idx]:
            ttb_scores[1] = 1.0
            break
            
    z_ttb = beta * (ttb_scores - np.max(ttb_scores))
    e_ttb = np.exp(z_ttb)
    p_ttb_dist = e_ttb / e_ttb.sum()
    
    # Tallying predictions
    a_wins = float(np.sum(stim[0] > stim[1]))
    b_wins = float(np.sum(stim[1] > stim[0]))
    tally_scores = np.array([a_wins, b_wins])
    
    z_tally = beta * (tally_scores - np.max(tally_scores))
    e_tally = np.exp(z_tally)
    p_tally_dist = e_tally / e_tally.sum()
    
    # Mixture of the two strategies
    p_core = p_ttb * p_ttb_dist + (1.0 - p_ttb) * p_tally_dist
    
    # Uniform lapse
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.9, 0.85, 0.65, 0.6, 0.55]

**Trial pairs (n=5):**
  trial 1: A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  trial 5: A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Rationale:** This design exploits the difference between 'Noisy TTB' (which assumes Gaussian noise on validities, causing features with similar validities to occasionally swap in the search hierarchy) and 'Strategy Mixture' (which assumes strict, noiseless TTB mixed with Tallying). By using validities where the top two features are very close (0.90 and 0.85) and the remaining features are lower, we can pit them against each other. In a trial where Option A has only feature 2 and Option B has only feature 1, Strategy Mixture predicts no preference for A (strict TTB chooses B, Tallying ties), while Noisy TTB predicts a significant preference for A due to validity swapping. Conversely, when Option A has feature 2 plus several lower-tier features and Option B has feature 1, Strategy Mixture predicts a jump in preference for A (since Tallying now strongly favors A), whereas Noisy TTB predicts the same choice probability as the first trial because the top two features still dominate the search process.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
Calculates the difference in the probability of choosing Option A between Trial 2 and Trial 1. Strategy Mixture predicts a large positive difference because Tallying shifts from a tie (in Trial 1) to strongly favoring Option A (in Trial 2). In contrast, Noisy TTB predicts a difference near zero because the top two validities (0.9 and 0.85) dominate the noisy search in both trials, meaning the extra lower-tier features in Trial 2 rarely impact the decision.

Source:
def metric(data: pd.DataFrame) -> float:
    a_tuple = data['option_a_ratings'].apply(tuple)
    t1_a = (0, 1, 0, 0, 0)
    t2_a = (0, 1, 1, 1, 0)
    
    t1_data = data[a_tuple == t1_a]
    t2_data = data[a_tuple == t2_a]
    
    p_a_t1 = (t1_data['response'] == 0).mean() if len(t1_data) > 0 else 0.0
    p_a_t2 = (t2_data['response'] == 0).mean() if len(t2_data) > 0 else 0.0
    
    return float(p_a_t2 - p_a_t1)

### RESULTS
- Predicted under pi_3 (simulated): 0.0853 (var=0.0269)
- Predicted under pi_4 (simulated): 0.2305 (var=0.0377)
- Observed on real data: -0.0063 (var=0.0098)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.75, 0.73, 0.71, 0.69]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 4: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 6: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 7: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 8: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]

**Rationale:** This design leverages a structural invariance in the Strategy Mixture model to cleanly dissociate it from Noisy TTB. We use a 5-feature environment where the most valid feature is highly diagnostic (0.95), while the remaining four features are clustered tightly together (0.75, 0.73, 0.71, 0.69). In Trial 1, Option A is supported only by the top feature (0.95), while Option B is supported by all four lower features. In Trial 2, Option A is supported only by the second-best feature (0.75), while Option B is supported by the bottom three. According to the Strategy Mixture model, both trials present the exact same conflict: strict TTB chooses Option A, and Tallying chooses Option B. Thus, the Strategy Mixture model predicts identical choice probabilities for Option A across both trials. In contrast, Noisy TTB predicts a much higher choice probability for Option A in Trial 1 (because the 0.95 validity is far enough above the rest to resist noise-induced rank swapping) than in Trial 2 (where the 0.75 validity is easily swapped with the tightly clustered lower features, leading to frequent choices of Option B). Additional trials vary the tallying margins to further constrain parameters.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the difference in the probability of choosing Option A between trials where Option A is supported by the highly diagnostic top feature (validity 0.95) versus trials where Option A is supported by the second-best feature (validity 0.75). According to the Strategy Mixture model, TTB strongly prefers A in both cases and Tallying strongly prefers B in both cases, leading to a similar mixture probability and a difference near zero. In contrast, Noisy TTB predicts a large difference because the 0.95 validity is robust to noise, whereas the 0.75 validity frequently swaps ranks with the closely clustered lower validities, leading to fewer choices of Option A in the second condition.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Convert ratings to a 2D numpy array
    a_ratings = np.stack(data['option_a_ratings'].values)
    
    # Trials 1, 3, 5, 7 have the top feature (index 0) active for Option A
    # Trials 2, 4, 6, 8 have the second-best feature (index 1) active for Option A, and index 0 is tied
    is_a0_1 = a_ratings[:, 0] == 1
    
    chose_a = (data['response'] == 0).values
    
    # Calculate the proportion of times Option A was chosen in each condition
    p_a_when_top_feature = np.mean(chose_a[is_a0_1])
    p_a_when_second_feature = np.mean(chose_a[~is_a0_1])
    
    return float(p_a_when_top_feature - p_a_when_second_feature)

### RESULTS
- Predicted under pi_3 (simulated): -0.0196 (var=0.0170)
- Predicted under pi_4 (simulated): -0.1308 (var=0.0125)
- Observed on real data: 0.0442 (var=0.0130)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_tuples = data['option_a_ratings'].apply(tuple)
    
    t1_mask = a_tuples == (0, 0, 1, 1, 1)
    t2_mask = a_tuples == (1, 1, 0, 0, 0)
    
    t1_tally_match = (data.loc[t1_mask, 'response'] == 0).sum()
    t2_tally_match = (data.loc[t2_mask, 'response'] == 1).sum()
    
    total = t1_mask.sum() + t2_mask.sum()
    if total == 0:
        return 0.5
        
    return float((t1_tally_match + t2_tally_match) / total)
```

**Observed (real) value:** 0.4863 (var=0.0089)
**Predicted under pi_3:** 0.4437 (var=0.0223)
**Predicted under pi_4:** 0.4519 (var=0.0649)

### Experiment 4
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Trial 1 pits an option with 3 low-validity features (A) against an option with 2 high-validity features (B).
    # Tallying strictly prefers A (3 wins vs 2 wins), leading to a response near 0.
    # WADD tends to prefer B, because the sum of the top 2 validities (0.9 + 0.8 = 1.7) 
    # is greater than the sum of the bottom 3 (0.6 + 0.5 + 0.5 = 1.6), leading to a higher rate of response 1.
    mask = data['option_a_ratings'].apply(lambda x: list(x) == [0, 0, 1, 1, 1])
    if mask.sum() == 0:
        return 0.0
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.5067 (var=0.0118)
**Predicted under pi_3:** 0.5017 (var=0.0285)
**Predicted under pi_4:** 0.4117 (var=0.0496)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np

    def is_wadd_choice(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        # Trial 1
        if a == (1, 0, 0, 0, 0) and b == (0, 1, 1, 1, 1):
            return resp == 1
        elif a == (0, 1, 1, 1, 1) and b == (1, 0, 0, 0, 0):
            return resp == 0
            
        # Trial 2
        elif a == (1, 0, 1, 0, 0) and b == (0, 1, 0, 1, 1):
            return resp == 1
        elif a == (0, 1, 0, 1, 1) and b == (1, 0, 1, 0, 0):
            return resp == 0
            
        # Trial 4
        elif a == (0, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            return resp == 1
        elif a == (0, 0, 1, 1, 1) and b == (0, 1, 0, 0, 0):
            return resp == 0
            
        return np.nan

    wadd_choices = data.apply(is_wadd_choice, axis=1)
    return float(wadd_choices.dropna().mean())
```

**Observed (real) value:** 0.4775 (var=0.0047)
**Predicted under pi_3:** 0.5908 (var=0.0120)
**Predicted under pi_4:** 0.5200 (var=0.0393)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    ttb_chosen = 0
    total = 0
    
    for idx, row in data.iterrows():
        a_str = ''.join(map(str, row['option_a_ratings']))
        b_str = ''.join(map(str, row['option_b_ratings']))
        resp = row['response']
        
        # Trial 1: 10000 vs 01111. TTB prefers 10000.
        if a_str == '10000' and b_str == '01111':
            ttb_chosen += 1 if resp == 0 else 0
            total += 1
        elif a_str == '01111' and b_str == '10000':
            ttb_chosen += 1 if resp == 1 else 0
            total += 1
            
        # Trial 3: 01000 vs 00111. TTB prefers 01000.
        elif a_str == '01000' and b_str == '00111':
            ttb_chosen += 1 if resp == 0 else 0
            total += 1
        elif a_str == '00111' and b_str == '01000':
            ttb_chosen += 1 if resp == 1 else 0
            total += 1
            
    if total == 0:
        return 0.5
    return float(ttb_chosen / total)
```

**Observed (real) value:** 0.5100 (var=0.0127)
**Predicted under pi_3:** 0.3725 (var=0.0154)
**Predicted under pi_4:** 0.4858 (var=0.0608)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed metrics are strikingly close to 0.5 for absolute choice proportions (Experiments 3-6) and close to 0.0 for differences in choice proportions across conditions (Experiments 1-2). Neither Noisy TTB (pi_3) nor Strategy Mixture (pi_4) consistently captures this profound regression to the mean. pi_4 predicts large deviations in Experiments 1 and 2 (0.2305 and -0.1308) where the observed differences are practically zero. pi_3 is closer on the first two experiments but fails significantly on Experiment 6 (predicting 0.3725 vs observed 0.5100). The robust tendency toward 0.5 suggests that subjects might not be systematically applying strict rule-based heuristics like TTB or Tallying in a way that leads to extreme choice probabilities. Instead, they may be using a noisy compensatory integration of all available information, heavily diluted by response noise or a high lapse rate.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Noisy Weighted Additive (WADD)' theory. Unlike TTB (which stops at the first discriminating feature) or Tallying (which ignores validities and counts wins), WADD assumes subjects compute a global value for each option by summing the validities of its active features. To capture the consistent ~0.5 choice probabilities and ~0.0 differences observed across all experiments, this model should incorporate a highly prominent noise mechanism (e.g., a low inverse temperature beta in a softmax function, or a high uniform lapse rate). This compensatory mechanism with high noise will naturally smooth out predictions and avoid the extreme deterministic swings predicted by Strategy Mixture or pure TTB."
}
```

## Usage

```json
{
  "prompt_token_count": 6868,
  "candidates_token_count": 391,
  "total_token_count": 8257
}
```
