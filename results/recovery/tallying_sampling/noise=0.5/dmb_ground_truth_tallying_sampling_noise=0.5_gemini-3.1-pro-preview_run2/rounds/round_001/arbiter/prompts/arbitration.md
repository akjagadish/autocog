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
People make decisions between options using a Tallying (Equal Weight) heuristic. Instead of weighting features by their validities or relying on a single discriminating cue, decision-makers simply count the number of positive features for each option. They choose the option with the higher total count, treating all cues as equally important. When counts are tied, they guess. Response noise is modeled via a softmax over the tally scores and a uniform lapse rate. The choice is relatively noisy, preventing the strategy from becoming perfectly deterministic even when one option has a clear tally advantage.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Tallying expects a (2, n_features) stimulus.")
    
    # Tallying: compute the sum of features for each option (equal weighting)
    scores = stim.sum(axis=1)
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the tally scores with max-subtraction for numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Blend with uniform lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()
    return int(np.random.choice(len(probs), p=probs))


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
**Validities (n_features=5):** [0.95, 0.85, 0.6, 0.55, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 4: A=[0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 5: A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Rationale:** To quantitatively dissociate Tallying (Equal Weight) from the Weighted Additive (WADD) rule, we use a 5-feature design with a skewed set of validities. In this design, some trials feature an option with fewer, but highly valid, cues pitted against an option with more, but less valid, cues. Tallying simply counts the number of positive features and will predict that the option with more features is chosen. WADD, conversely, weights each feature by its validity and will predict that the option with higher total validity is chosen. By including trials where Tallying predicts a strong preference for one option while WADD predicts the opposite, as well as trials where one model predicts a tie while the other predicts a clear winner, we can distinctly identify which strategy subjects are employing.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
In Trial 3, both Option A and Option B have exactly one positive feature. The Tallying model evaluates this as a perfect tie (1 vs 1) and will predict a 50% chance of choosing A for every subject, with any deviation from 0.5 being purely due to binomial sampling noise. WADD, however, assigns subjective weights to the specific features present. Because these weights vary and are unlikely to be perfectly equal, WADD will systematically prefer one option over the other for any given subject. By calculating the mean per-subject absolute deviation from a 0.5 choice proportion on this trial, we expect a value close to 0 (specifically, the expected absolute deviation of a Binomial(16, 0.5)/16) for Tallying, and a significantly larger value for WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    # Identify Trial 3 where both options have exactly 1 positive feature.
    # Tallying predicts a perfect tie (score 1 vs 1) for all subjects.
    # WADD predicts a preference based on subjective weights for the specific features.
    def is_t3(row):
        return sum(row['option_a_ratings']) == 1 and sum(row['option_b_ratings']) == 1
    
    mask = data.apply(is_t3, axis=1)
    t3_data = data[mask]
    
    if len(t3_data) == 0:
        return 0.0
        
    # Calculate each subject's absolute deviation from 0.5 probability of choosing A
    subject_devs = []
    for subj, subj_df in t3_data.groupby('subject_id'):
        pA = (subj_df['response'] == 0).mean()
        subject_devs.append(abs(pA - 0.5))
        
    if not subject_devs:
        return 0.0
        
    return float(np.mean(subject_devs))

### RESULTS
- Predicted under pi_3 (simulated): 0.0988 (var=0.0038)
- Predicted under pi_2 (simulated): 0.2900 (var=0.0195)
- Observed on real data: 0.1000 (var=0.0041)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.9, 0.7, 0.6, 0.5, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 3: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 6: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 7: A=[1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 8: A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Rationale:** To quantitatively dissociate WADD from Tallying (Equal Weight), this design pairs options such that the two models produce divergent predictions. We use a 5-feature setup with validities strategically chosen so that a small number of highly valid cues can perfectly balance a larger number of less valid cues. The trials include cases where WADD predicts a tie but Tallying predicts a strong preference (because one option has more positive features), cases where Tallying predicts a tie (equal number of positive features) but WADD predicts a strong preference (due to higher validity weights), and cases where the two models predict completely opposite choices. This multi-pronged dissociation ensures that the models are distinguishable not just by overall accuracy, but by their trial-by-trial choice directions and confidence.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times the subject chose the option [0, 0, 1, 1, 1] over the option [1, 1, 0, 0, 0]. Under the Weighted Additive (WADD) model with validities [0.9, 0.7, 0.6, 0.5, 0.5], both options have exactly the same weighted sum (1.6), so WADD predicts subjects will guess (a choice proportion of 0.5). Under the Tallying (Equal Weight) model, the option [0, 0, 1, 1, 1] has a higher sum (3 vs 2), so Tallying predicts it will be chosen consistently above chance. By focusing exclusively on these perfectly balanced trials, we can maximally discriminate between the two decision rules.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    def is_11000(x):
        return tuple(x) == (1, 1, 0, 0, 0)
    
    def is_00111(x):
        return tuple(x) == (0, 0, 1, 1, 1)

    a_11000 = data['option_a_ratings'].apply(is_11000)
    b_00111 = data['option_b_ratings'].apply(is_00111)
    
    a_00111 = data['option_a_ratings'].apply(is_00111)
    b_11000 = data['option_b_ratings'].apply(is_11000)
    
    trial_1 = a_11000 & b_00111
    trial_2 = a_00111 & b_11000
    
    mask = trial_1 | trial_2
    subset = data[mask]
    if len(subset) == 0:
        return 0.5
        
    chose_00111 = (trial_1 & (data['response'] == 1)) | (trial_2 & (data['response'] == 0))
    chose_00111_subset = chose_00111[mask]
    
    return float(chose_00111_subset.mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.6583 (var=0.0175)
- Predicted under pi_2 (simulated): 0.4475 (var=0.0872)
- Observed on real data: 0.7017 (var=0.0062)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    diff = a_mat - b_mat
    weights = np.array([1000, 100, 10, 1])
    score_diff = diff @ weights
    ttb_preds = np.where(score_diff > 0, 0, 1)
    matches = (data['response'].values == ttb_preds)
    return float(np.mean(matches))
```

**Observed (real) value:** 0.3504 (var=0.0026)
**Predicted under pi_3:** 0.3846 (var=0.0045)
**Predicted under pi_2:** 0.4281 (var=0.0279)

### Experiment 4
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    mask = sum_b > sum_a
    if mask.sum() == 0:
        return 0.0
    return float(data.loc[mask, 'response'].mean())
```

**Observed (real) value:** 0.6741 (var=0.0053)
**Predicted under pi_3:** 0.6930 (var=0.0104)
**Predicted under pi_2:** 0.6756 (var=0.0280)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (Tallying / Equal Weight) provides a much better fit to the observed data than Theory 2 (Weighted Additive). In Experiment 1, Tallying correctly predicts the near-zero deviation from chance when options have an equal number of positive features, whereas WADD predicts a much larger deviation due to subjective weighting. In Experiment 2, Tallying correctly predicts the strong preference for the option with more positive features (0.70 observed vs 0.66 predicted), whereas WADD predicts subjects will guess or slightly prefer the other option. Tallying also tracks the metrics in Experiments 3 and 4 closely. Because WADD consistently fails to capture the prominent feature-counting behavior of the subjects, it should be replaced.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace the Weighted Additive (WADD) theory with a radically different heuristic from the fast-and-frugal family, such as the 'Take-The-Best' (TTB) or a Lexicographic heuristic. TTB searches through cues in order of their validity and stops at the first cue that discriminates between the options, ignoring all other cues. This would provide a strictly non-compensatory, rank-based alternative to the equal-weight compensatory nature of Tallying, allowing us to test whether subjects are simply counting cues (Tallying) or relying on the single most valid discriminating cue."
}
```

## Usage

```json
{
  "prompt_token_count": 5380,
  "candidates_token_count": 324,
  "total_token_count": 6587
}
```
