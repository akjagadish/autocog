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
Generalized Weighted Additive (WADD) Theory: Decision-makers evaluate options by computing a compensatory weighted sum of their features. However, instead of using raw cue validities as weights, individuals scale the validities non-linearly using a parameter gamma. This scaling allows the decision process to smoothly interpolate between Tallying (gamma=0, where all cues are weighted equally), standard WADD (gamma=1), and Take The Best (gamma -> infinity, where the most valid cue dominates). The final choice is made probabilistically via a softmax function over the computed option values, mixed with a random lapse rate.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != stim.shape[1]:
        raise ValueError("Length of validities must match number of features.")
        
    gamma = float(parameters["gamma"])
    weights = val ** gamma
    
    a, b = stim[0], stim[1]
    
    # Calculate weighted sums for each option
    score_a = np.sum(weights * a)
    score_b = np.sum(weights * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over scores with max-subtraction for numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_2
People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
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
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 7: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** This design strictly dissociates Generalized Weighted Additive (WADD) Theory from Tallying. Tallying ignores cue validities and simply counts the number of features favoring each option, treating all features equally. WADD, on the other hand, weights features by their non-linearly scaled validities (parameterized by gamma). The trials are carefully constructed to include: (1) pairs where Tallying predicts a tie (equal number of winning features) but WADD strongly prefers one option due to validity differences; (2) pairs where Tallying prefers one option because it wins on more features, but WADD prefers the other because its fewer winning features have a higher combined validity (even at gamma=1); and (3) pairs that distinguish different ranges of the WADD gamma parameter, where Tallying and WADD (at gamma=1) agree, but WADD at higher gamma values (approaching Take The Best) flips its preference.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Focuses strictly on trials where Tallying and WADD make diametrically opposite predictions. On these trials, one option has more positive features (3 vs 2), which Tallying strictly prefers. However, the option with fewer features contains the two most valid cues, which WADD strictly prefers (even at gamma=1). Tallying will yield a metric near 0 (minus noise), while WADD will yield a metric near 1 (minus noise).

Source:
def metric(data: pd.DataFrame) -> float:
    wadd_choices = 0
    total = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            if resp == 0:
                wadd_choices += 1
            total += 1
        elif a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            if resp == 1:
                wadd_choices += 1
            total += 1
            
    return wadd_choices / total if total > 0 else 0.5

### RESULTS
- Predicted under pi_3 (simulated): 0.8067 (var=0.0433)
- Predicted under pi_2 (simulated): 0.1283 (var=0.0105)
- Observed on real data: 0.4800 (var=0.0233)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 3: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 4: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Rationale:** To quantitatively dissociate Tallying from Generalized WADD, we must exploit the fact that Tallying strictly ignores cue validities (effectively fixing the WADD gamma parameter to 0). In this design, we pit the sheer number of winning features against the validities of those features. Several trials are constructed such that Tallying predicts a strict tie (equal number of winning features) while WADD predicts a strong preference for the option with the higher-validity feature. Other trials present a scenario where one option has fewer winning features but higher validities (benefiting WADD with gamma >= 1), while the other option has more winning features of lower validity (favored by Tallying). If subjects use Tallying, they will show indifference on the tied trials and a preference for the option with more winning features on the others, a pattern WADD can only fit by collapsing gamma to 0.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the difference in choice proportions (specifically, the probability of choosing option B) between Trial 4 and Trial 3. In Trial 3, Tallying counts more winning features for A (3 vs 2), predicting a preference for A, while Generalized WADD (with gamma > ~1) heavily weights B's top features, predicting a preference for B. Conversely, in Trial 4, Tallying counts more winning features for B (3 vs 2), whereas WADD weights A's top feature strongly, predicting a preference for A. Subtracting the response rate of Trial 3 from Trial 4 yields a strongly positive value for Tallying and a strongly negative value for Generalized WADD, perfectly dissociating the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Identify Trial 3: A=[0, 0, 1, 1, 1], B=[1, 1, 0, 0, 0]
    # Tallying favors A (3 vs 2), meaning response should be closer to 0.
    # WADD with gamma > 1 favors B (due to the 0.95 and 0.85 validities), meaning response closer to 1.
    is_trial_3 = data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))
    
    # Identify Trial 4: A=[1, 0, 0, 1, 0], B=[0, 1, 1, 0, 1]
    # Tallying favors B (2 vs 3), meaning response should be closer to 1.
    # WADD with gamma > 1 favors A (due to the 0.95 validity), meaning response closer to 0.
    is_trial_4 = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 0, 0, 1, 0))
    
    resp_3 = data.loc[is_trial_3, 'response'].mean()
    resp_4 = data.loc[is_trial_4, 'response'].mean()
    
    if pd.isna(resp_3):
        resp_3 = 0.5
    if pd.isna(resp_4):
        resp_4 = 0.5
        
    # Tallying: resp_4 (high) - resp_3 (low) -> Positive
    # WADD: resp_4 (low) - resp_3 (high) -> Negative
    return float(resp_4 - resp_3)

### RESULTS
- Predicted under pi_3 (simulated): -0.2850 (var=0.2349)
- Predicted under pi_2 (simulated): 0.6825 (var=0.0634)
- Observed on real data: -0.0025 (var=0.0589)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_matches = 0
    valid_trials = 0
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        
        # TTB compares cues in order 0 to n_features-1
        ttb_choice = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_choice = 0
                break
            elif b[i] > a[i]:
                ttb_choice = 1
                break
                
        if ttb_choice is not None:
            if row['response'] == ttb_choice:
                ttb_matches += 1
            valid_trials += 1
            
    return float(ttb_matches / valid_trials) if valid_trials > 0 else 0.5
```

**Observed (real) value:** 0.4737 (var=0.0046)
**Predicted under pi_3:** 0.4486 (var=0.0430)
**Predicted under pi_2:** 0.1516 (var=0.0131)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    tally_a = np.sum(a_ratings > b_ratings, axis=1)
    tally_b = np.sum(b_ratings > a_ratings, axis=1)
    valid = tally_a != tally_b
    if not np.any(valid):
        return 0.5
    pred = np.where(tally_a > tally_b, 0, 1)
    return float((pred[valid] == data['response'].values[valid]).mean())
```

**Observed (real) value:** 0.5479 (var=0.0020)
**Predicted under pi_3:** 0.5290 (var=0.0541)
**Predicted under pi_2:** 0.8823 (var=0.0065)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, the observed metrics consistently hover around the exact values expected by random guessing (e.g., 0.5 for binary match rates, 0.0 for difference metrics). For instance, in Experiment 1 the observed metric is 0.48 (indifference), in Experiment 2 it is -0.0025 (indifference), in Experiment 3 the TTB match rate is 0.47, and in Experiment 4 the Tallying match rate is 0.54. Neither Generalized WADD (pi_3) nor Tallying (pi_2) accurately captures this behavior, as both predict strong directional preferences on these carefully crafted adversarial trials. pi_3's predictions only occasionally align with the data when its parameters randomly simulate high noise, while pi_2 systematically fails. The data strongly suggests that subjects are not systematically employing any of the structured compensatory or non-compensatory heuristics proposed so far, but are instead guessing.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace the Tallying theory with a 'Random Guessing' or 'Zero-Intelligence' theory. The new theory should posit that without trial-by-trial feedback, subjects find the multi-attribute binary feature task too cognitively demanding or unengaging, leading them to simply guess uniformly at random on every trial. The predict function should return exactly [0.5, 0.5] for all stimulus pairs, ignoring validities and feature values entirely."
}
```

## Usage

```json
{
  "prompt_token_count": 5353,
  "candidates_token_count": 337,
  "total_token_count": 7134
}
```
