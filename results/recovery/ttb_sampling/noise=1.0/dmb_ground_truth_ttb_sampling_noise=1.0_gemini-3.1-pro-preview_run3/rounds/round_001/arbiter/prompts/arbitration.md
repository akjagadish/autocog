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
**Validities (n_features=5):** [0.95, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 3: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]

**Rationale:** To dissociate the non-compensatory Take-The-Best (TTB) model from the compensatory Weighted Additive (WADD) model, we use a 5-feature environment. The validities range from very high (0.95) to chance (0.50). We designed trials where the option favored by the single most valid cue is pitted against an option supported by multiple less valid cues. TTB, which stops at the first discriminating feature, will consistently choose the option with the highest valid cue. In contrast, WADD integrates all cues and will often prefer the option with multiple lesser cues because their combined weight exceeds that of the single best cue. Additional trials where the models agree or marginally disagree provide constraints on the noise and weighting parameters.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times the subject chooses the option favored by the Weighted Additive (WADD) model over the option favored by the Take-The-Best (TTB) heuristic on the critical trials (Trials 1, 2, and 4). On these trials, TTB relies on the single most valid discriminating cue, whereas WADD integrates the remaining cues to override the best cue. The metric will be close to 0 for TTB and close to 1 for WADD.

Source:
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

### RESULTS
- Predicted under pi_3 (simulated): 0.5908 (var=0.0120)
- Predicted under pi_2 (simulated): 0.7438 (var=0.0146)
- Observed on real data: 0.4775 (var=0.0047)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 5: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 7: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 8: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Rationale:** To quantitatively dissociate the compensatory Weighted Additive (WADD) model from the non-compensatory Noisy Take-The-Best (TTB) model, we use a 5-feature environment with linearly decreasing validities. The design systematically pits the single most valid cue (or the top two) against a coalition of multiple less valid cues. Because TTB searches features in order of noisy validity and stops at the first discriminating cue, it will predominantly choose the option favored by the highest-validity feature. In contrast, WADD integrates all features, allowing the combined weight of several lower-validity features to easily overcome the single best feature. By varying the margin of WADD's preference and the probability that Noisy TTB samples the critical feature first, we can cleanly separate the two models.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of choices that align with the non-compensatory Take-The-Best (TTB) model on the most strongly diagnostic trials (Trial 1 and Trial 3). In these trials, a single highly valid cue favors one option while a coalition of several less valid cues favors the other. TTB predicts the single best cue will dominate, leading to a high proportion of choices for that option. WADD, being compensatory, integrates the multiple lower-validity cues which easily outweigh the single best cue, predicting the opposite choice. The difference in this proportion between the two models will be stark.

Source:
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

### RESULTS
- Predicted under pi_3 (simulated): 0.3725 (var=0.0154)
- Predicted under pi_2 (simulated): 0.2142 (var=0.0235)
- Observed on real data: 0.5100 (var=0.0127)

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
**Predicted under pi_2:** 0.4738 (var=0.0772)

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
**Predicted under pi_2:** 0.4108 (var=0.0539)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, the observed metric values are strikingly close to 0.5 (0.4775, 0.5100, 0.4863, 0.5067). The experiments were explicitly designed to pit a non-compensatory strategy (Take-The-Best, which favors a single high-validity cue) against a compensatory strategy (WADD or Tallying, which favors a coalition of lesser cues). Because the aggregate behavior consistently centers around chance on these conflict trials, neither a purely non-compensatory model (like Theory 1) nor a purely compensatory model (like Theory 2) captures the data effectively. Theory 2 (WADD) makes strong deterministic predictions that are far from the observed 0.5 mark. Theory 1 (Noisy TTB) gets closer only by virtue of high noise, which is a weak explanation. The consistent ~0.5 aggregate rate on polarized trials strongly suggests population heterogeneity: roughly half the subjects (or half the trials) employ a non-compensatory strategy, and the other half employ a compensatory one, perfectly offsetting each other in the aggregate.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Strategy Mixture' theory. Instead of assuming all subjects use WADD or TTB, this theory should posit that the population is heterogeneous, consisting of a mix of decision-makers. On any given trial, the decision is made either via a non-compensatory heuristic (Take-The-Best) or a compensatory heuristic (Tallying / Equal Weights), governed by a mixing parameter (e.g., proportion of TTB users). When these strategies conflict (as in the experimental designs), the opposing choices average out, naturally capturing the ~0.5 aggregate choice proportions observed across all experiments without relying solely on massive uniform noise."
}
```

## Usage

```json
{
  "prompt_token_count": 5623,
  "candidates_token_count": 411,
  "total_token_count": 7451
}
```
