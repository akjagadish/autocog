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


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.65, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 4: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 6: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 7: A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  trial 8: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Rationale:** This design quantitatively dissociates Tallying from the Weighted Additive (WADD) rule using a five-feature structure. We use validities that are spread out, allowing WADD to strongly prefer options with fewer but highly valid features, while Tallying simply counts feature-wise wins. Some trials create a direct conflict (e.g., Option A wins on the two highest-validity features, while Option B wins on the three lowest, causing WADD to prefer A and Tallying to prefer B). Other trials result in an equal number of feature wins for both options (e.g., 1 vs 1 or 2 vs 2), causing Tallying to predict complete indifference, whereas WADD predicts strong preferences based on the asymmetric validities of the winning features.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Trial 1 is carefully designed to pit the two theories against each other in opposite directions. Option A wins on the two highest-validity features, while Option B wins on the three lowest-validity features. Tallying strictly prefers Option B because it wins on more features (3 vs 2). WADD strictly prefers Option A because the sum of the validities for A's features (1.8) is greater than the sum for B's features (1.7). By measuring the proportion of trials where a subject chooses Option A, we get a clear divergence: Tallying predicts a value below 0.5, whereas WADD predicts a value above 0.5.

Source:
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

### RESULTS
- Predicted under pi_1 (simulated): 0.1650 (var=0.0196)
- Predicted under pi_2_1 (simulated): 0.6417 (var=0.0184)
- Observed on real data: 0.7133 (var=0.0245)

## EXPERIMENT 2 (proposed by pi_2_1)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=5):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 4: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0]
  trial 5: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** This design quantitatively dissociates the Weighted Additive (WADD) theory from Tallying using five features with skewed validities. Trial 1 pits the two highest-validity features against the three lowest, creating a direct conflict where WADD prefers the option with fewer, higher-validity features (Option A), while Tallying prefers the option with more feature wins (Option B). Trials 2, 3, and 4 feature ties in the number of feature wins (2 vs 2 or 3 vs 3), leading Tallying to predict complete indifference (guessing). In contrast, WADD predicts clear preferences on these trials based on the specific validities of the winning features. Trial 5 serves as a control where both models agree on the preferred option but diverge on the strength of preference.

**Computed schedule:** 5 unique pairs × 19 reps = 95 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times the subject chose the option [1, 1, 0, 0, 0] over [0, 0, 1, 1, 1] in Trial 1. The WADD model strongly prefers [1, 1, 0, 0, 0] because the combined validity of the first two features (0.95 + 0.90 = 1.85) outweighs the last three (0.60 + 0.55 + 0.50 = 1.65). In contrast, the Tallying model strictly prefers [0, 0, 1, 1, 1] because it wins on three features compared to two. This creates a maximal, directional divergence between the two theories, ensuring a large and robust gap in the metric.

Source:
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

### RESULTS
- Predicted under pi_1 (simulated): 0.1768 (var=0.0115)
- Predicted under pi_2_1 (simulated): 0.7337 (var=0.0171)
- Observed on real data: 0.6695 (var=0.0161)

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
**Predicted under pi_1:** 0.8569 (var=0.0086)
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
**Predicted under pi_1:** 0.8558 (var=0.0129)
**Predicted under pi_2_1:** 0.2450 (var=0.0191)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, the Weighted Additive model (THEORY 2) consistently and accurately predicts the observed data, while Tallying (THEORY 1) completely fails. The experiments were specifically designed to pit the two theories against each other by presenting pairs where one option wins on fewer but more important features (favored by WADD), and the other wins on more but less important features (favored by Tallying). In every case, human subjects overwhelmingly chose the options with the higher-validity features, aligning with WADD and directly contradicting Tallying. Because Tallying ignores cue validities entirely, it is deeply misaligned with human behavior in this domain.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace Tallying with 'Take The Best' (TTB). TTB is a lexicographic, non-compensatory heuristic where decision-makers compare options sequentially starting from the cue with the highest validity. If the options differ on that cue, the decision is made immediately based on it; if they tie, the decision-maker moves to the next highest validity cue, and so on. This provides a much stronger and more realistic competitor to WADD: it respects cue validities (unlike Tallying) but processes them in a fundamentally non-compensatory way (unlike WADD)."
}
```

## Usage

```json
{
  "prompt_token_count": 5509,
  "candidates_token_count": 297,
  "total_token_count": 6592
}
```
