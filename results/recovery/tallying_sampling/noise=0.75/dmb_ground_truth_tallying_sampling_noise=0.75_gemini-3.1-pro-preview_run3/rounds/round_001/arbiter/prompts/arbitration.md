# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_3" and "pi_2") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_3" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_3
Decision-makers use a 'Tallying' (Equal-Weight) heuristic, a compensatory strategy that ignores cue validities. They simply count the number of positive features (or advantages) each option has and choose the option with the highest total count. If the counts are equal, they guess. Because pure Tallying makes choices that strongly oppose Take The Best on compensatory trials, high levels of choice stochasticity (noise) are needed to pull the predicted consistency up toward the observed ~0.40-0.42 range, reflecting uncertainty or lapses in applying the heuristic.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    
    # Tallying: sum the unweighted feature values for each option.
    scores = stim.sum(axis=1)
    
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
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_2
People compare two options by computing, for each option, a weighted sum of its feature values, where each feature is weighted by its subjective validity (or importance). The option with the higher weighted sum is chosen. WADD is the compensatory benchmark against which one-reason heuristics like Take The Best are contrasted: a large deficit on a high-validity cue can be compensated by a sufficiently strong advantage on lower-validity cues, so no single feature is ever decisive on its own. Unlike Tallying, WADD uses cardinal feature magnitudes and weights them by validity, so it exploits both the sign and the size of each feature-wise comparison as well as inter-cue differences in informativeness. Unlike Equal-Weight, weights differ across features. Behavior is invariant to a shared affine rescaling across options but scales linearly with per-feature weight. When the two weighted sums are equal the model has no basis for preference and the learner must guess. Response noise enters through a softmax over the two weighted sums with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Weighted Additive rule (Payne, Bettman & Johnson
    # 1993). Stimulus is the pair of option feature vectors for the
    # current trial: array-like of shape (2, n_features), row 0 =
    # option A, row 1 = option B. Each option's score is the dot
    # product of its feature vector with the (subjective) validity
    # weights. History is ignored: the choice depends only on the
    # current stimulus.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    validities = np.asarray(parameters["validities"], dtype=float)
    w = np.asarray(parameters["weights"], dtype=float)
    if w.shape[0] != n_features:
        raise ValueError(
            f"weights length {w.shape[0]} != n_features {n_features}."
        )

    # Weighted sum per option (dot product with per-feature weights).
    scores = stim @ (validities * w)

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    # Uniform lapse blended into the softmax (standard choice-with-lapse
    # formulation; epsilon=0.5 yields equiprobable options, matching
    # the paper's maximum-noise condition).
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 5: A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 6: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 7: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 8: A=[0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0]

**Rationale:** To robustly dissociate Tallying (which simply counts the number of positive features, ignoring validities) from the Weighted Additive rule (WADD, which weights each feature by its validity), we use 5 features with a steep drop-off in validities. The critical dissociation trials pit an option with a greater number of low-validity features (favored by Tallying) against an option with fewer, but much higher-validity features (favored by WADD). We also include tie-breaking trials where Tallying sees equal feature counts but WADD has a strict preference, as well as agreement trials to anchor the baseline and constrain noise parameters.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
By taking advantage of four specific trials, we can completely control for Tallying while isolating WADD's effect. Under Tallying, Trials 1, 5, 7, and 8 all have an exact feature count difference of +1 in favor of Option A. Therefore, Tallying predicts identical choice probabilities for Option A across all four trials, meaning the difference between the average choice probability of (Trial 5 + Trial 7) and (Trial 1 + Trial 8) will be precisely 0 in expectation, with low variance due to averaging. Under WADD, Option A is strongly favored in Trials 5 and 7 (average WADD score difference of +0.625) but neutral/disfavored in Trials 1 and 8 (average WADD score difference of -0.05). Thus, WADD predicts a substantially positive difference, robustly discriminating the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, map(int, x))))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, map(int, x))))
    
    def get_mask(a_target, b_target):
        m1 = (a_str == a_target) & (b_str == b_target)
        m2 = (a_str == b_target) & (b_str == a_target)
        return m1, m2
    
    t1_m1, t1_m2 = get_mask('00111', '11000')
    t5_m1, t5_m2 = get_mask('00110', '00001')
    t7_m1, t7_m2 = get_mask('01110', '10001')
    t8_m1, t8_m2 = get_mask('00111', '10100')
    
    def get_p_a(m1, m2):
        mask = m1 | m2
        if not mask.any():
            return 0.5
        chose_a = np.where(m1, data['response'] == 0, data['response'] == 1)
        return float(chose_a[mask].mean())
    
    p_a_t1 = get_p_a(t1_m1, t1_m2)
    p_a_t5 = get_p_a(t5_m1, t5_m2)
    p_a_t7 = get_p_a(t7_m1, t7_m2)
    p_a_t8 = get_p_a(t8_m1, t8_m2)
    
    group1_p = (p_a_t5 + p_a_t7) / 2.0
    group2_p = (p_a_t1 + p_a_t8) / 2.0
    
    return float(group1_p - group2_p)

### RESULTS
- Predicted under pi_3 (simulated): 0.0183 (var=0.0170)
- Predicted under pi_2 (simulated): 0.2392 (var=0.1175)
- Observed on real data: -0.0383 (var=0.0218)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.55, 0.5, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 4: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]

**Rationale:** To robustly dissociate the Weighted Additive (WADD) rule from the Tallying heuristic, we employ a 5-feature design with a steep validity curve. Tallying simply counts the number of positive features, whereas WADD weights each feature by its validity. The critical dissociation trials pit an option with fewer but high-validity features (favored by WADD) against an option with more but low-validity features (favored by Tallying). Additionally, we include trials where Tallying predicts a tie (equal number of positive features) but WADD has a strict preference, to further highlight the use of validity weights.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of choices that align with the Weighted Additive (WADD) model on the critical dissociation trials (Trials 1 and 6). On these trials, one option has fewer features but they are the highest validity ones (features 1 and 2), while the other option has more features but they are lower validity (features 3, 4, 5). The WADD model strongly prefers the option with the high-validity features, whereas the Tallying model prefers the option with the greater number of features. Consequently, WADD will score highly on this metric, while Tallying will score poorly (below 0.5, depending on noise levels).

Source:
def metric(data: pd.DataFrame) -> float:
    a_tuples = data['option_a_ratings'].apply(tuple)
    b_tuples = data['option_b_ratings'].apply(tuple)
    
    t1_mask = (a_tuples == (1, 1, 0, 0, 0)) & (b_tuples == (0, 0, 1, 1, 1))
    t6_mask = (a_tuples == (0, 0, 1, 1, 1)) & (b_tuples == (1, 1, 0, 0, 0))
    
    t1_wadd_match = (data['response'] == 0) & t1_mask
    t6_wadd_match = (data['response'] == 1) & t6_mask
    
    relevant_trials = t1_mask | t6_mask
    if not relevant_trials.any():
        return 0.5
        
    return float((t1_wadd_match.sum() + t6_wadd_match.sum()) / relevant_trials.sum())

### RESULTS
- Predicted under pi_3 (simulated): 0.4512 (var=0.0076)
- Predicted under pi_2 (simulated): 0.6331 (var=0.0834)
- Observed on real data: 0.4012 (var=0.0049)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_consistent = 0
    total = 0
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        # Features are already sorted by validity in descending order.
        # Find the first discriminating cue.
        ttb_choice = -1
        for j in range(len(a)):
            if a[j] > b[j]:
                ttb_choice = 0
                break
            elif b[j] > a[j]:
                ttb_choice = 1
                break
                
        if ttb_choice != -1:
            if resp == ttb_choice:
                ttb_consistent += 1
            total += 1
            
    return ttb_consistent / total if total > 0 else 0.5
```

**Observed (real) value:** 0.4249 (var=0.0029)
**Predicted under pi_3:** 0.4247 (var=0.0036)
**Predicted under pi_2:** 0.3453 (var=0.0144)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = [0.9, 0.8, 0.7, 0.6]
    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        
        # TTB choice
        ttb = -1
        for i in range(4):
            if a[i] > b[i]: 
                ttb = 0
                break
            elif b[i] > a[i]: 
                ttb = 1
                break
                
        # Expected WADD choice (with equal subjective weights)
        score_a = sum(a[i] * validities[i] for i in range(4))
        score_b = sum(b[i] * validities[i] for i in range(4))
        wadd = 0 if score_a > score_b else (1 if score_b > score_a else -1)
        
        # Only consider trials where TTB and WADD diverge
        if ttb != -1 and wadd != -1 and ttb != wadd:
            matches.append(1.0 if row['response'] == ttb else 0.0)
            
    return float(np.mean(matches)) if len(matches) > 0 else 0.5
```

**Observed (real) value:** 0.4027 (var=0.0071)
**Predicted under pi_3:** 0.4300 (var=0.0059)
**Predicted under pi_2:** 0.2787 (var=0.0354)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, Theory 1 (Tallying / Equal-Weight) consistently outperforms Theory 2 (Weighted Additive). In Experiment 1, the observed metric (-0.0383) closely aligns with Tallying's prediction (0.0183) and contradicts WADD's prediction of a strong positive difference (0.2392). In Experiment 2, the WADD-match proportion on dissociation trials is 0.4012, showing subjects actually prefer the option with more features (Tallying) rather than higher-validity features (WADD). Experiments 3 and 4 further confirm that subjects systematically choose against TTB and WADD in favor of raw feature counts. Theory 2 (WADD) completely fails to capture this robust reliance on unweighted feature counting.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace the WADD theory with a 'Take-The-Best' (TTB) heuristic theory. TTB searches through cues in descending order of validity and stops at the first cue that discriminates between the options, choosing the option favored by that cue. While the data currently strongly points toward Tallying (as subjects consistently prefer options with more total features regardless of validity), formally introducing TTB will provide the classic fast-and-frugal non-compensatory competitor to Tallying, allowing the system to definitively contrast an equal-weight compensatory rule (Tallying) against a lexicographic one (TTB)."
}
```

## Usage

```json
{
  "prompt_token_count": 5730,
  "candidates_token_count": 339,
  "total_token_count": 7285
}
```
