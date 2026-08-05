# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_2_1") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2_1" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
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


## THEORY 2 — pi_2_1
People compare two options by computing, for each option, a weighted sum of its feature values, where each feature is weighted by its subjective validity (or importance). The option with the higher weighted sum is chosen. WADD is the compensatory benchmark against which one-reason heuristics like Take The Best are contrasted: a large deficit on a high-validity cue can be compensated by a sufficiently strong advantage on lower-validity cues, so no single feature is ever decisive on its own. Unlike Tallying, WADD uses cardinal feature magnitudes and weights them by validity, so it exploits both the sign and the size of each feature-wise comparison as well as inter-cue differences in informativeness. Unlike Equal-Weight, weights differ across features. Behavior is invariant to a shared affine rescaling across options but scales linearly with per-feature weight. When the two weighted sums are equal the model has no basis for preference and the learner must guess. Response noise enters through a softmax over the two weighted sums with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    validities = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Apply subjective distortion to validities
    subjective_weights = validities ** gamma
    
    # Weighted sum per option (dot product with subjective weights)
    scores = stim @ subjective_weights
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
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
    probabilities /= probabilities.sum()  # Ensure valid probabilities
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=6):** [0.99, 0.95, 0.6, 0.55, 0.5, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  trial 2: A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  trial 3: A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  trial 4: A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  trial 5: A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  trial 7: A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  trial 8: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]

**Rationale:** This design uses a 6-feature environment with a pronounced drop-off in validities to robustly separate Tallying from WADD. Tallying counts the number of features favoring each option, ignoring validities. WADD computes a weighted sum. By pitting a small number of high-validity features against a larger number of low-validity features, we create critical trials where Tallying chooses the option with more winning features while WADD chooses the option that wins on the most important ones. We also include trials where Tallying predicts a tie but WADD strongly prefers one option, as well as trials where both models agree. This diversity of trial types ensures a clear quantitative dissociation.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of choices consistent with Tallying on the critical 'mismatch' trials where Tallying and WADD strongly disagree. For example, when Option A has more winning features but Option B has the highest-validity features, Tallying prefers A while WADD prefers B. This targeted proportion will be much higher under Tallying than under WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    tally_choices = 0
    total_mismatch = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        if a == (0, 0, 1, 1, 1, 0) and b == (1, 1, 0, 0, 0, 0):
            tally_choices += (resp == 0)
            total_mismatch += 1
        elif a == (0, 0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0, 0):
            tally_choices += (resp == 0)
            total_mismatch += 1
        elif a == (1, 1, 0, 0, 0, 0) and b == (0, 0, 1, 1, 1, 0):
            tally_choices += (resp == 1)
            total_mismatch += 1
            
    return float(tally_choices / total_mismatch) if total_mismatch > 0 else 0.5


### RESULTS
- Predicted under pi_1 (simulated): 0.8644 (var=0.0110)
- Predicted under pi_2_1 (simulated): 0.1983 (var=0.0373)
- Observed on real data: 0.3256 (var=0.0090)

## EXPERIMENT 2 (proposed by pi_2_1)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 7: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 8: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]

**Rationale:** To robustly dissociate the Weighted Additive (WADD) rule from the Tallying heuristic, this design employs a 5-feature environment with a pronounced bimodal distribution of validities (two highly valid features and three low-validity features). Tallying counts the number of strict feature-wise wins, treating all features equally regardless of validity. In contrast, WADD scales the feature values by their subjective validities. By pairing options where one wins on a few high-validity features while the other wins on a greater number of low-validity features, Tallying predicts a choice for the latter, whereas WADD predicts a choice for the former. We also include trials where Tallying predicts a tie (equal number of winning features) but WADD strongly prefers the option with higher-validity features, as well as trials where the models agree, providing a comprehensive quantitative dissociation.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric isolates trials where the two options are [1, 1, 0, 0, 0] and [0, 0, 1, 1, 1]. In these trials, the WADD model generally prefers the option with two highly valid features (the first two), because their combined subjective weight outweighs the three less valid features. In contrast, the Tallying heuristic strictly counts the number of features won and strongly prefers the option with three winning features over the one with two. By computing the proportion of times the subject chooses the option with fewer but higher-validity features, we expect a high value under WADD and a low value under Tallying.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    a_is_11000 = np.all(a_ratings == [1, 1, 0, 0, 0], axis=1)
    b_is_00111 = np.all(b_ratings == [0, 0, 1, 1, 1], axis=1)
    
    a_is_00111 = np.all(a_ratings == [0, 0, 1, 1, 1], axis=1)
    b_is_11000 = np.all(b_ratings == [1, 1, 0, 0, 0], axis=1)
    
    trial_type_1 = a_is_11000 & b_is_00111
    trial_type_2 = a_is_00111 & b_is_11000
    
    target_trials = trial_type_1 | trial_type_2
    
    if not np.any(target_trials):
        return 0.5
        
    responses = data['response'].values
    
    wadd_chosen = np.zeros_like(responses, dtype=bool)
    wadd_chosen[trial_type_1 & (responses == 0)] = True
    wadd_chosen[trial_type_2 & (responses == 1)] = True
    
    return float(np.mean(wadd_chosen[target_trials]))

### RESULTS
- Predicted under pi_1 (simulated): 0.1400 (var=0.0145)
- Predicted under pi_2_1 (simulated): 0.7767 (var=0.0555)
- Observed on real data: 0.6717 (var=0.0180)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    tallying_choices = 0
    total_relevant = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        if a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            if resp == 0:
                tallying_choices += 1
            total_relevant += 1
        elif a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            if resp == 1:
                tallying_choices += 1
            total_relevant += 1
    if total_relevant == 0:
        return 0.5
    return tallying_choices / total_relevant
```

**Observed (real) value:** 0.3400 (var=0.0108)
**Predicted under pi_1:** 0.8517 (var=0.0133)
**Predicted under pi_2_1:** 0.2625 (var=0.0762)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify the specific trial where WADD and Tallying strongly disagree.
    # Trial: A=[1, 1, 0, 0, 0] vs B=[0, 0, 1, 1, 1]
    # WADD prefers A (validity sum 1.8 > 1.7) while Tallying prefers B (tally 3 > 2).
    mask = data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))
    if mask.sum() == 0:
        return 0.5
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.3567 (var=0.0242)
**Predicted under pi_1:** 0.8683 (var=0.0120)
**Predicted under pi_2_1:** 0.2350 (var=0.0560)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, the Weighted Additive model (THEORY 2, WADD) consistently outperforms the Tallying heuristic (THEORY 1). Tallying repeatedly predicts that subjects will strongly prefer the option with a greater number of winning features, even if those features have low validity. However, the observed data shows subjects reliably choosing the option with fewer but higher-validity features. While WADD captures this compensatory behavior well, replacing the completely degenerate Tallying theory with a stronger, non-compensatory alternative that respects cue validities would provide a more rigorous test for WADD.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace Tallying with the Take-The-Best (TTB) heuristic. Unlike Tallying, TTB is sensitive to cue validities but uses them in a strictly non-compensatory (lexicographic) manner. TTB evaluates features one by one in descending order of their subjective validity. The first feature that discriminates between the two options (i.e., one option has a 1 and the other has a 0) entirely determines the choice, and remaining features are ignored. This will provide a strong non-compensatory competitor to WADD that can actually predict the observed preference for high-validity features."
}
```

## Usage

```json
{
  "prompt_token_count": 5638,
  "candidates_token_count": 289,
  "total_token_count": 6899
}
```
