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
People make choices by computing a weighted sum of all available features for each option, but the weights they use are a non-linear transformation of the objective cue validities. By exponentiating the validities with a free parameter gamma, the strategy can smoothly interpolate between equal weighting (Tallying, gamma=0) and a strong reliance on the most valid cues (approximating Take The Best, gamma > 1). The choice is then made probabilistically based on the difference between the options' weighted sums, with a bounded inverse temperature beta to allow for more stochastic choices.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) state; got shape {stim.shape}.")
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Non-linear scaling of validities
    subjective_weights = val ** gamma
    
    # Calculate weighted sums for both options
    a, b = stim[0], stim[1]
    score_a = np.sum(a * subjective_weights)
    score_b = np.sum(b * subjective_weights)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax choice with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate response noise (lapse rate)
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()  # Ensure valid probabilities
    return int(np.random.choice(len(probs), p=probs))


## THEORY 2 — pi_4
Decision makers employ a dual-process or strategy mixture approach when evaluating multi-attribute options. Rather than relying entirely on a single strategy, choices are generated by a probabilistic mixture of a simple, unweighted Tallying heuristic (which counts the number of strictly winning features) and a compensatory Weighted Additive (WADD) strategy (which integrates all features weighted by their subjective validities). To ensure equitable application of choice determinism, the evidence scores for both strategies are normalized to a common [0, 1] scale before applying a shared inverse temperature parameter. The mixture parameter 'alpha' dictates the reliance on Tallying versus WADD, allowing the model to capture exact chance-level responding in scenarios where features tie while maintaining sensitivity to cue validities in general.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) state; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    beta = float(parameters["beta"])
    alpha = float(parameters["alpha"])
    epsilon = float(parameters["epsilon"])
    
    # WADD Component: Weighted sum using non-linearly scaled validities, normalized to [0, 1]
    subjective_weights = val ** gamma
    sum_weights = np.sum(subjective_weights)
    score_a_wadd = np.sum(a * subjective_weights) / sum_weights
    score_b_wadd = np.sum(b * subjective_weights) / sum_weights
    scores_wadd = np.array([score_a_wadd, score_b_wadd])
    
    z_wadd = beta * (scores_wadd - np.max(scores_wadd))
    e_wadd = np.exp(z_wadd)
    p_wadd = e_wadd / np.sum(e_wadd)
    
    # Tallying Component: Count of strict feature-wise wins, normalized to [0, 1]
    a_wins = float(np.sum(a > b)) / n_features
    b_wins = float(np.sum(b > a)) / n_features
    scores_tally = np.array([a_wins, b_wins])
    
    z_tally = beta * (scores_tally - np.max(scores_tally))
    e_tally = np.exp(z_tally)
    p_tally = e_tally / np.sum(e_tally)
    
    # Mixture of the two strategies
    p_mixed = alpha * p_tally + (1.0 - alpha) * p_wadd
    
    # Incorporate response noise (lapse rate)
    return (1.0 - epsilon) * p_mixed + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=8):** [1.0, 0.95, 0.9, 0.85, 0.8, 0.75, 0.7, 0.65]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1]
  trial 3: A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1]
  trial 4: A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 0]
  trial 5: A=[1, 0, 0, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 0, 0, 0, 0]
  trial 6: A=[0, 1, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 1, 1]

**Rationale:** This design quantitatively dissociates the pure Weighted Additive (WADD) model (Advocated) from the Mixture model (Competing) by exploiting a structural difference in how they scale evidence. The Competing model normalizes the WADD score difference by the sum of all subjective weights before applying the inverse temperature 'beta'. By using 8 features with high validities, the sum of weights becomes very large (e.g., > 6.5). The pure WADD model does not normalize by the sum of weights. Consequently, for trials where the unnormalized score difference is moderate but the total sum of weights is large, the pure WADD model can easily predict highly deterministic choices (using its beta parameter up to 5.0). In contrast, the Competing model divides this score difference by ~6.5, shrinking it so much that even with its maximum beta of 10.0, it is mathematically incapable of predicting the same level of determinism. By including trials where Tallying predicts a tie (further drawing the Mixture model toward 0.5) alongside trials with varying WADD score differences, we create a regime where the Advocated model can capture high choice probabilities that the Competing model strictly underpredicts.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Measures the choice probability of Option A on Trial 1. On this trial, the pure WADD model (Advocated) will predict a highly deterministic choice for Option A because the unnormalized score difference is easily scaled by its beta parameter to produce a probability close to 1.0. In contrast, the Mixture model (Competing) strictly normalizes the score difference by the sum of all weights (which is large for 8 high-validity features), shrinking the effective difference so much that even its maximum beta cannot push the choice probability as high. Additionally, Tallying predicts a tie on this trial, further anchoring the Mixture model's prediction toward 0.5.

Source:
def metric(data: pd.DataFrame) -> float:
    data['is_t1'] = data.apply(
        lambda row: tuple(row['option_a_ratings']) == (1, 1, 1, 1, 0, 0, 0, 0) and 
                    tuple(row['option_b_ratings']) == (0, 0, 0, 0, 1, 1, 1, 1),
        axis=1
    )
    t1_data = data[data['is_t1']]
    if len(t1_data) == 0:
        return 0.5
    return float((t1_data['response'] == 0).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.7887 (var=0.0209)
- Predicted under pi_4 (simulated): 0.5437 (var=0.0168)
- Observed on real data: 0.5550 (var=0.0310)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=6):** [0.95, 0.85, 0.75, 0.65, 0.6, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  trial 3: A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  trial 4: A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  trial 5: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  trial 6: A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  trial 7: A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]

**Rationale:** To quantitatively dissociate the Mixture model (Advocated) from the pure WADD model (Competing), we exploit the Mixture model's independent Tallying component and its normalization of evidence. The pure WADD model uses a single non-linear transformation (gamma) to interpolate between equal weighting and lexicographic (Take-The-Best) choice. It cannot simultaneously exhibit strong sensitivity to the number of winning features (Tallying) on some trials while acting highly compensatory on others, because a single gamma parameter locks in the scaling. By contrast, the Mixture model can explicitly blend a pure count of features (Tallying) with a compensatory evaluation (WADD). We include trials where Tallying predicts a tie but WADD predicts a strong preference, trials where WADD predicts a near-tie but Tallying predicts a strong preference, and trials where the two strategies strongly oppose each other. Because the Mixture model normalizes both WADD and Tallying scores to a [0, 1] scale before applying the inverse temperature, it will uniquely capture choice probabilities that reflect an explicit blend of unweighted feature counting and normalized weighted addition.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
We contrast trials where the Tallying heuristic favors Option A (Trials 6 and 7) against trials where Tallying predicts a tie (Trials 3 and 4). For the pure WADD model, the difference in weighted sums between A and B is actually larger in the tie trials than in the Tallying-favored trials at high values of the gamma parameter, meaning pure WADD will frequently predict a higher probability of choosing A in Trials 3 and 4 than in 6 and 7. In contrast, the Mixture model explicitly incorporates the Tallying heuristic, which consistently boosts the probability of choosing A in Trials 6 and 7 while diluting it toward 0.5 in Trials 3 and 4. By measuring (P(A|T6) + P(A|T7)) - (P(A|T3) + P(A|T4)), the Mixture model yields a robustly positive score, whereas the pure WADD model yields a near-zero or negative score. Combining four trials halves the binomial noise compared to a two-trial contrast, reducing between-subject variance and sharply increasing discriminability.

Source:
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_tuple'] = data['option_a_ratings'].apply(tuple)
    
    # Tallying heavily favors A in these trials
    t7_A = (1, 0, 0, 1, 1, 1)
    t6_A = (0, 0, 1, 1, 1, 0)
    
    # Tallying predicts an exact tie in these trials
    t3_A = (1, 1, 1, 0, 0, 0)
    t4_A = (0, 1, 1, 1, 0, 0)
    
    m7 = data[data['A_tuple'] == t7_A]['response'].mean()
    m6 = data[data['A_tuple'] == t6_A]['response'].mean()
    m3 = data[data['A_tuple'] == t3_A]['response'].mean()
    m4 = data[data['A_tuple'] == t4_A]['response'].mean()
    
    # Response is 0 for A, 1 for B. P(A) = 1 - mean(response)
    p_A_t7 = 1.0 - m7
    p_A_t6 = 1.0 - m6
    p_A_t3 = 1.0 - m3
    p_A_t4 = 1.0 - m4
    
    return float((p_A_t7 + p_A_t6) - (p_A_t3 + p_A_t4))

### RESULTS
- Predicted under pi_3 (simulated): -0.2383 (var=0.1589)
- Predicted under pi_4 (simulated): 0.1517 (var=0.1130)
- Observed on real data: 0.0400 (var=0.2001)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.array(data['option_a_ratings'].tolist())
    b_mat = np.array(data['option_b_ratings'].tolist())
    
    ttb_choices = []
    for a, b in zip(a_mat, b_mat):
        choice = 0.5
        for i in range(len(a)):
            if a[i] > b[i]:
                choice = 0
                break
            elif b[i] > a[i]:
                choice = 1
                break
        ttb_choices.append(choice)
        
    ttb_choices = np.array(ttb_choices)
    responses = data['response'].values
    
    valid = ttb_choices != 0.5
    if not np.any(valid):
        return 0.5
        
    return float(np.mean(responses[valid] == ttb_choices[valid]))
```

**Observed (real) value:** 0.4408 (var=0.0085)
**Predicted under pi_3:** 0.4402 (var=0.0132)
**Predicted under pi_4:** 0.4198 (var=0.0092)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    # Tallying counts the number of features where one option strictly dominates the other
    a_wins = np.sum(a_mat > b_mat, axis=1)
    b_wins = np.sum(b_mat > a_mat, axis=1)
    
    tally_pred = np.zeros(len(data))
    tally_pred[b_wins > a_wins] = 1
    tally_pred[a_wins == b_wins] = -1 # Ignore ties for matching purposes
    
    matches = (data['response'].values == tally_pred)
    valid = (tally_pred != -1)
    
    return float(np.mean(matches[valid])) if np.any(valid) else 0.5
```

**Observed (real) value:** 0.6317 (var=0.0047)
**Predicted under pi_3:** 0.6663 (var=0.0137)
**Predicted under pi_4:** 0.6877 (var=0.0084)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    target = (1, 1, 0, 0, 0)
    other = (0, 0, 1, 1, 0)
    a_keys = data['option_a_ratings'].apply(tuple)
    b_keys = data['option_b_ratings'].apply(tuple)
    mask = ((a_keys == target) & (b_keys == other)) | ((a_keys == other) & (b_keys == target))
    if not mask.any():
        return 0.5
    rel_data = data[mask]
    chosen_a = rel_data['response'] == 0
    a_is_target = a_keys[mask] == target
    chose_target = (chosen_a & a_is_target) | (~chosen_a & ~a_is_target)
    return float(chose_target.mean())
```

**Observed (real) value:** 0.5133 (var=0.0354)
**Predicted under pi_3:** 0.7067 (var=0.0378)
**Predicted under pi_4:** 0.5783 (var=0.0312)

### Experiment 6
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    mask = ((a_str == '10100') & (b_str == '01010')) | ((a_str == '01100') & (b_str == '00011'))
    
    target_data = data[mask]
    if len(target_data) == 0:
        return 0.5
        
    return float((target_data['response'] == 0).mean())
```

**Observed (real) value:** 0.5400 (var=0.0176)
**Predicted under pi_3:** 0.6417 (var=0.0197)
**Predicted under pi_4:** 0.5792 (var=0.0147)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, Theory 2 (pi_4, the Mixture of Tallying and WADD) consistently outperforms Theory 1 (pi_3, Pure WADD with non-linear scaling). In Experiment 1, pi_3 predicts highly deterministic choices (0.788) because it lacks a normalization mechanism for the sum of weights, whereas the observed data is nearly at chance (0.555). Theory 2 captures this much better (0.543) by explicitly incorporating a Tallying component that predicts a tie and normalizing the evidence. Similarly, in Experiments 5 and 6, pi_3 significantly overpredicts the probability of choosing the WADD-favored option, whereas the observed data remains close to 0.5, which Theory 2 handles better. However, Theory 2 is not perfect either, suggesting that the compensatory WADD component might still be too complex or misaligned with human bounded rationality. Theory 1's pure compensatory approach is degenerate for this domain, as subjects clearly exhibit heuristic-like, equal-weighting behavior (Tallying) on many trials.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace the pure WADD model with a 'Probabilistic Heuristic Toolbox' theory. Instead of assuming compensatory weighted addition (WADD), propose that subjects probabilistically sample from a set of fast-and-frugal heuristics on each trial: specifically, a mixture of 'Take-The-Best' (TTB, a purely lexicographic strategy that decides based solely on the most valid discriminating feature) and 'Tallying' (equal weighting of all features). This avoids complex non-linear scaling and compensatory integration entirely, positing instead that choices reflect a probabilistic execution of distinct, boundedly rational heuristics. The model should include a parameter governing the probability of deploying TTB versus Tallying, and a shared lapse/noise parameter."
}
```

## Usage

```json
{
  "prompt_token_count": 7027,
  "candidates_token_count": 420,
  "total_token_count": 9056
}
```
