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


## THEORY 2 — pi_5
Noisy Weighted Additive (WADD) Model: Decision-makers compute a global value for each option by summing the validities of its active features. Rather than relying on a single discriminating feature (like Take-The-Best) or ignoring validities (like Tallying), WADD integrates all available validities compensatorily. To account for the highly consistent ~0.5 choice probabilities and near-zero differences observed across the experiments, the decision process incorporates a highly prominent noise mechanism. This is modeled via a very low inverse temperature in the softmax choice rule and a potentially high uniform lapse rate, smoothing out predictions and avoiding deterministic swings.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # WADD: Sum of validities for active features for each option
    scores = np.sum(stim * validities, axis=1)
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Blend with uniform lapse rate
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=5):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate Noisy Take-The-Best (TTB) from the highly noisy Weighted Additive (WADD) model, we exploit both the structural differences (non-compensatory vs. compensatory) and the distinct noise regimes parameterized for each theory. The competing WADD model is restricted to a very high lapse rate (epsilon >= 0.5) and low inverse temperature (beta <= 0.5), forcing its predictions to be highly compressed toward 0.5, while always leaning toward the option with the highest sum of validities. In contrast, the advocated Noisy TTB model can exhibit much sharper choice probabilities (epsilon as low as 0.0) and relies on sequential search. We design trials that pit the single most valid feature against a coalition of lesser features. In these trials, Noisy TTB strongly predicts a preference for the option favored by the top feature, whereas the WADD model predicts a slight preference (barely above chance) for the option with the coalition of lesser features. This opposing directionality combined with the stark difference in predicted choice extremity provides a robust dissociation.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
This metric calculates the difference in the probability of choosing Option A between Trial 5 and Trial 1. In Trial 1, Option A is supported only by the single most valid feature, while Option B is supported by all other four features. The compensatory WADD model heavily favors Option B here, while the non-compensatory TTB model favors Option A. In Trial 5, Option A is supported by the second and third most valid features, while Option B is supported by the fourth and fifth. Here, both models favor Option A (though TTB's preference might be slightly weaker than in Trial 1 because the discriminating feature is less valid). By subtracting the proportion of choosing A in Trial 1 from Trial 5, we expect a positive value for WADD (since it shifts from favoring B to favoring A) and a negative or near-zero value for TTB (which strongly favors A in Trial 1 and slightly less strongly in Trial 5). This difference in signs provides a strong qualitative dissociation.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def is_t1(row):
        return tuple(row['option_a_ratings']) == (1, 0, 0, 0, 0) and tuple(row['option_b_ratings']) == (0, 1, 1, 1, 1)
    
    def is_t5(row):
        return tuple(row['option_a_ratings']) == (0, 1, 1, 0, 0) and tuple(row['option_b_ratings']) == (0, 0, 0, 1, 1)
        
    t1_mask = data.apply(is_t1, axis=1)
    t5_mask = data.apply(is_t5, axis=1)
    
    p_a_t1 = np.mean(data[t1_mask]['response'] == 0) if t1_mask.sum() > 0 else 0.5
    p_a_t5 = np.mean(data[t5_mask]['response'] == 0) if t5_mask.sum() > 0 else 0.5
    
    return float(p_a_t5 - p_a_t1)

### RESULTS
- Predicted under pi_3 (simulated): 0.1842 (var=0.0255)
- Predicted under pi_5 (simulated): 0.0168 (var=0.0232)
- Observed on real data: -0.0316 (var=0.0199)

## EXPERIMENT 2 (proposed by pi_5)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=5):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 3: A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 4: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 5: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Rationale:** To quantitatively dissociate the highly noisy Weighted Additive (WADD) model from the Noisy Take-The-Best (TTB) model, we exploit both the compensatory vs. non-compensatory structural differences and their distinct noise assumptions. The advocated WADD model assumes decisions are compensatory but heavily smoothed by high lapse rates and low inverse temperatures, predicting a slight but consistent preference for the option with the highest sum of validities. In contrast, Noisy TTB predicts sharper preferences dictated primarily by the single most valid cue. By pitting a single highly valid feature against a coalition of multiple slightly less valid features, WADD predicts a muted preference for the coalition, whereas Noisy TTB predicts a strong preference for the single best feature. Observing a reliable but weak preference for the coalition would support the highly noisy WADD account over TTB.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
The highly noisy WADD model is parameterized to make choice probabilities extremely close to 0.5 across all trials due to high lapse rates and low inverse temperatures. The Noisy TTB model, however, makes much stronger predictions depending on the subject's sampled validities and feature orders. By calculating the mean absolute deviation of each trial type's choice proportion from 0.5, we can quantify the 'extremeness' of preferences. To ensure the pooled point estimate accurately reflects the per-subject expectation (and avoids artificial deflation due to large pooled sample sizes), the metric explicitly computes the absolute deviation on a per-subject basis before averaging.

Source:
def metric(data: pd.DataFrame) -> float:
    def subj_metric(df):
        keys = df['option_a_ratings'].apply(tuple)
        p_A = 1.0 - df.groupby(keys)['response'].mean()
        return float((p_A - 0.5).abs().mean())
    
    return float(data.groupby('subject_id').apply(subj_metric).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.1417 (var=0.0051)
- Predicted under pi_5 (simulated): 0.0939 (var=0.0008)
- Observed on real data: 0.0979 (var=0.0009)

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
**Predicted under pi_5:** 0.5012 (var=0.0086)

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
**Predicted under pi_5:** 0.4758 (var=0.0103)

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
**Predicted under pi_5:** 0.5021 (var=0.0064)

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
**Predicted under pi_5:** 0.4725 (var=0.0091)

### Experiment 7
**Design**
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_tuple = data['option_a_ratings'].apply(tuple)
    t1_a = (0, 1, 0, 0, 0)
    t2_a = (0, 1, 1, 1, 0)
    
    t1_data = data[a_tuple == t1_a]
    t2_data = data[a_tuple == t2_a]
    
    p_a_t1 = (t1_data['response'] == 0).mean() if len(t1_data) > 0 else 0.0
    p_a_t2 = (t2_data['response'] == 0).mean() if len(t2_data) > 0 else 0.0
    
    return float(p_a_t2 - p_a_t1)
```

**Observed (real) value:** -0.0063 (var=0.0098)
**Predicted under pi_3:** 0.0853 (var=0.0269)
**Predicted under pi_5:** 0.0179 (var=0.0218)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]

**Metric**
```python
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
```

**Observed (real) value:** 0.0442 (var=0.0130)
**Predicted under pi_3:** -0.0196 (var=0.0170)
**Predicted under pi_5:** 0.0083 (var=0.0095)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all eight experiments, the observed metrics consistently show near-zero differences or choice probabilities hovering around 0.5. THEORY 2 (pi_5, Noisy WADD) tracks these muted, highly noisy observed values much better than THEORY 1 (pi_3, Noisy TTB), which consistently predicts overly sharp preferences and larger effect sizes (e.g., in Experiments 1, 5, 6, and 7). The consistent failure of TTB to capture the near-random choice behavior suggests that a non-compensatory, validity-ordered search process does not describe the subjects' decision-making in this paradigm. Instead, subjects appear to either guess or use a highly simplified compensatory strategy that ignores complex validities.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Noisy Tallying' (or Equal Weights) theory. Instead of sorting features by validity (TTB) or computing weighted sums (WADD), decision-makers simply count the total number of positive features (1s) for each option and choose the one with the higher count. To capture the extreme smoothing seen in the data, this Tallying model must be coupled with a high lapse rate and a low inverse temperature, predicting choices that are only slightly biased toward the option with more positive features."
}
```

## Usage

```json
{
  "prompt_token_count": 7536,
  "candidates_token_count": 296,
  "total_token_count": 8558
}
```
