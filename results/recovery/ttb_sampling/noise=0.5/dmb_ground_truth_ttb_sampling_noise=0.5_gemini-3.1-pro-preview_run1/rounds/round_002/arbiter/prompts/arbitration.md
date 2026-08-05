# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_2_1") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2_1" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
Take The Best (TTB) is a lexicographic, non-compensatory heuristic. Decision-makers evaluate options by comparing them sequentially on features, starting with the cue that has the highest subjective validity. The first feature that discriminates between the options determines the choice. If all features tie, the decision-maker guesses. Response noise is modeled as an independent lapse rate that occasionally results in a random choice.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    a, b = stim[0], stim[1]
    p_core = np.array([0.5, 0.5])  # Default to guessing if all features tie
    
    # Sequential comparison
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    n_opts = p_core.shape[0]
    
    # Blend deterministic TTB choice with uniform lapse
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_2_1
People compare two options by computing, for each option, a weighted sum of its feature values, where each feature is weighted by its subjective validity (or importance). The option with the higher weighted sum is chosen. WADD is the compensatory benchmark against which one-reason heuristics like Take The Best are contrasted: a large deficit on a high-validity cue can be compensated by a sufficiently strong advantage on lower-validity cues, so no single feature is ever decisive on its own. Unlike Tallying, WADD uses cardinal feature magnitudes and weights them by validity, so it exploits both the sign and the size of each feature-wise comparison as well as inter-cue differences in informativeness. Unlike Equal-Weight, weights differ across features. Behavior is invariant to a shared affine rescaling across options but scales linearly with per-feature weight. When the two weighted sums are equal the model has no basis for preference and the learner must guess. Response noise enters through a softmax over the two weighted sums with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    # Paper-faithful Weighted Additive rule (WADD)
    # Stimulus is the pair of option feature vectors for the
    # current trial: array-like of shape (2, n_features), row 0 =
    # option A, row 1 = option B. 
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    # Use the experiment-provided validities directly as the weights.
    validities = np.asarray(parameters["validities"], dtype=float)

    # Weighted sum per option (dot product with validities).
    scores = stim @ validities

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Uniform lapse blended into the softmax
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.8, 0.7, 0.65]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 4: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 5: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  trial 6: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]

**Rationale:** This design quantitatively dissociates Take The Best (TTB) from the Weighted Additive rule (WADD) by exploiting the compensatory versus non-compensatory distinction. In these trials, one option always possesses the single most valid discriminating feature (which TTB relies on exclusively), while the other option possesses a greater number of slightly less valid features whose combined weight exceeds that of the single best feature (which WADD favors). By creating these direct conflicts across different validity levels and including trials with tied top features, we can cleanly distinguish the lexicographic stopping rule of TTB from the compensatory integration of WADD.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
The experimental design pits Take The Best (TTB) against the Weighted Additive rule (WADD) such that they predict exactly opposite choices on every single trial. TTB relies on the single highest-validity discriminating feature, while WADD integrates all features, allowing multiple lower-validity features to compensate and override the top feature. By calculating the proportion of choices that align with TTB's prediction, we expect a value near 1.0 for data generated under TTB and a value near 0.0 for data generated under WADD. This creates a maximal contrast between the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_match = 0
    total = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        # Features are pre-sorted by validity in descending order based on the design.
        # TTB evaluates features sequentially.
        ttb_pred = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred == resp:
            ttb_match += 1
        total += 1
        
    return float(ttb_match / total) if total > 0 else 0.0

### RESULTS
- Predicted under pi_3 (simulated): 0.7556 (var=0.0186)
- Predicted under pi_2_1 (simulated): 0.2069 (var=0.0085)
- Observed on real data: 0.6896 (var=0.0029)

## EXPERIMENT 2 (proposed by pi_2_1)

### DESIGN
**Validities (n_features=5):** [0.95, 0.75, 0.65, 0.55, 0.5]

**Trial pairs (n=5):**
  trial 1: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 2: A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 4: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]

**Rationale:** This design strongly dissociates the non-compensatory Take The Best (TTB) heuristic from the compensatory Weighted Additive (WADD) rule. By assigning validities that are relatively spread out but still allow for compensation, we create trials where one option wins on the single most valid discriminating feature (which strictly dictates TTB's choice), while the other option wins on a larger number of slightly less valid features such that its overall weighted sum is higher (which dictates WADD's choice). The design includes conflicts at the first, second, and third most valid features by tying the higher-validity features, ensuring that the dissociation is robust across different stopping points of the lexicographic TTB process.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
The experimental design was specifically constructed to perfectly dissociate the Weighted Additive (WADD) rule from Take The Best (TTB). On every single trial type, the option favoured by TTB (which relies on the single highest-validity discriminating cue) is opposed by WADD (which compensates for this deficit using multiple lower-validity cues). By calculating the proportion of choices that align with the WADD prediction, we get a metric that will be near 1.0 for the WADD model and near 0.0 for the TTB model. This maximal separation combined with low within-model variance guarantees strong discrimination between the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    w = np.array([0.95, 0.75, 0.65, 0.55, 0.5])
    
    def wadd_choice(row):
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        score_a = np.dot(a, w)
        score_b = np.dot(b, w)
        return 0 if score_a > score_b else 1
        
    predicted = data.apply(wadd_choice, axis=1)
    return np.mean(data['response'] == predicted)


### RESULTS
- Predicted under pi_3 (simulated): 0.2371 (var=0.0204)
- Predicted under pi_2_1 (simulated): 0.8596 (var=0.0118)
- Observed on real data: 0.3234 (var=0.0041)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    v = np.array([1.0, 0.9, 0.8, 0.7, 0.6, 0.5])
    
    tally_matches = 0
    disagreement_trials = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        wadd_a = np.dot(a, v)
        wadd_b = np.dot(b, v)
        
        tally_pref = None
        if a_wins > b_wins:
            tally_pref = 0
        elif b_wins > a_wins:
            tally_pref = 1
            
        wadd_pref = None
        if wadd_a > wadd_b:
            wadd_pref = 0
        elif wadd_b > wadd_a:
            wadd_pref = 1
            
        if tally_pref is not None and wadd_pref is not None and tally_pref != wadd_pref:
            disagreement_trials += 1
            if row['response'] == tally_pref:
                tally_matches += 1
                
    if disagreement_trials == 0:
        return 0.5
        
    return float(tally_matches / disagreement_trials)
```

**Observed (real) value:** 0.3500 (var=0.0088)
**Predicted under pi_3:** 0.2437 (var=0.0293)
**Predicted under pi_2_1:** 0.3844 (var=0.0199)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def tally_match(row):
        sum_a = sum(row['option_a_ratings'])
        sum_b = sum(row['option_b_ratings'])
        if sum_a > sum_b:
            return 1.0 if row['response'] == 0 else 0.0
        elif sum_b > sum_a:
            return 1.0 if row['response'] == 1 else 0.0
        else:
            return np.nan
            
    matches = data.apply(tally_match, axis=1)
    return float(matches.dropna().mean())
```

**Observed (real) value:** 0.3283 (var=0.0114)
**Predicted under pi_3:** 0.2250 (var=0.0228)
**Predicted under pi_2_1:** 0.2450 (var=0.0191)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify the specific trial where Tallying and WADD have opposite strict preferences.
    # Trial 1: Option A has features [1, 1, 0, 0, 0] and Option B has [0, 0, 1, 1, 1].
    # Tallying prefers B (3 wins vs 2 wins).
    # WADD prefers A (0.95 + 0.85 = 1.8 vs 0.65 + 0.55 + 0.5 = 1.7).
    is_target = (data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))) & \
                (data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1)))
    
    target_data = data[is_target]
    if len(target_data) == 0:
        return 0.5
        
    # Return the proportion of times Option A was chosen
    return float((target_data['response'] == 0).mean())
```

**Observed (real) value:** 0.7133 (var=0.0245)
**Predicted under pi_3:** 0.7650 (var=0.0277)
**Predicted under pi_2_1:** 0.6417 (var=0.0184)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    def get_target_choice(row):
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            return 1.0 if row['response'] == 0 else 0.0
        elif a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            return 1.0 if row['response'] == 1 else 0.0
        return np.nan

    choices = data.apply(get_target_choice, axis=1)
    val = np.nanmean(choices)
    if np.isnan(val):
        return 0.5
    return float(val)
```

**Observed (real) value:** 0.6695 (var=0.0161)
**Predicted under pi_3:** 0.7800 (var=0.0231)
**Predicted under pi_2_1:** 0.7337 (var=0.0171)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the six experiments, Take The Best (Theory 1) consistently outperforms the Weighted Additive rule (Theory 2) in extreme dissociation cases. In Experiment 1, observed behavior aligns with TTB 69% of the time, which TTB captures well (76%) while WADD completely misses (21%). In Experiment 2, the metric measures alignment with WADD; the observed value is only 32%, which TTB correctly anticipates (24%) because it predicts opposite choices, whereas WADD expects 86% alignment. However, neither theory perfectly captures Experiments 3 and 4, where observed metrics sit between the two extremes, suggesting that subjects might not be purely lexicographic but rather use a rank-based discounting or a mixture of strategies. Since WADD categorically fails on Experiments 1 and 2, it should be replaced.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a new theory such as 'Rank-Dependent Weighting' or a 'Strategy Selection / Mixture' model. A Rank-Dependent Weighting model would assign subjective weights to features based solely on their validity rank (e.g., exponentially decaying weights) rather than their raw validity values. This would allow the model to behave non-compensatorily (like TTB) when the decay is steep, but still integrate multiple cues when the top cues tie or when the decay is moderate, better capturing the intermediate variance seen in Experiments 3 and 4 without completely failing on the strict dissociation designs of Experiments 1 and 2."
}
```

## Usage

```json
{
  "prompt_token_count": 6182,
  "candidates_token_count": 344,
  "total_token_count": 7519
}
```
