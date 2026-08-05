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
People compare two options by tallying the number of positive features for each option, treating all cues as equally important and completely ignoring their provided validities. This Tallying (or Equal-Weight) heuristic is a simple compensatory strategy that is less cognitively demanding than the Weighted Additive (WADD) rule but avoids relying on just a single feature like Take-The-Best (TTB). The option with the higher tally is chosen. When the tallies are tied, the decision-maker has no basis for preference and guesses uniformly. Response noise is incorporated through a softmax function over the tally scores with an inverse temperature parameter (beta), plus an independent lapse rate (epsilon) that occasionally replaces the choice with a uniform random guess.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    # Tallying: simply count the number of positive features for each option
    scores = np.sum(stim, axis=1)
    
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
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
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
**Validities (n_features=5):** [0.99, 0.98, 0.52, 0.51, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 4: A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  trial 7: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 8: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0]

**Rationale:** To quantitatively dissociate Tallying (Equal-Weight) from WADD, we use a 5-feature design with an extreme bimodal distribution of validities: two very high validities and three very low validities. Tallying simply counts the number of positive features, completely ignoring their validities, whereas WADD computes a weighted sum. We construct critical trials where Tallying prefers the option with more positive features (e.g., 3 low-validity cues), but WADD strongly prefers the alternative (e.g., 2 high-validity cues). We also include tie-breaking trials where Tallying sees an equal number of positive features (and thus guesses randomly), while WADD has a strong preference based on cue validity. Baseline trials where both models agree are included to estimate overall response noise.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of choices that align with the Tallying heuristic specifically on critical trials where Tallying and WADD make opposite predictions. On these trials, one option has 3 positive features with low validity, while the other has 2 positive features with high validity. Tallying will consistently prefer the option with 3 features (yielding a metric near 1.0), whereas WADD will strongly prefer the option with 2 high-validity features (yielding a metric near 0.0).

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    b_str = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Trial 1: A has 3 low-validity cues, B has 2 high-validity cues
    is_trial_1 = (a_str == '00111') & (b_str == '11000')
    # Trial 2: A has 2 high-validity cues, B has 3 low-validity cues
    is_trial_2 = (a_str == '11000') & (b_str == '00111')
    
    mask = is_trial_1 | is_trial_2
    if not mask.any():
        return 0.5
        
    # Tallying prefers the option with 3 positive features
    tally_correct_1 = is_trial_1 & (data['response'] == 0)
    tally_correct_2 = is_trial_2 & (data['response'] == 1)
    
    return float((tally_correct_1 | tally_correct_2).sum() / mask.sum())

### RESULTS
- Predicted under pi_3 (simulated): 0.7875 (var=0.0299)
- Predicted under pi_2 (simulated): 0.4708 (var=0.1009)
- Observed on real data: 0.4833 (var=0.0088)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.65, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  trial 6: A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 7: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Rationale:** This design quantitatively dissociates the Weighted Additive (WADD) rule from the Tallying (Equal-Weight) heuristic. By using five features with a steep drop-off in validities (two high, three low), we create critical trials where a smaller number of highly valid features strongly outweighs a larger number of low-validity features. In these trials, WADD predicts preference for the option with fewer but better features, while Tallying counts purely positive cues and prefers the alternative. The design includes trials with direct opposition, trials where one model predicts a tie while the other shows a strong preference, and baseline trials where both agree, enabling a precise estimation of noise and strategy fit.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Trial 1 (A=[1,1,0,0,0], B=[0,0,1,1,1]) is the critical trial that dissociates the two models. Tallying relies purely on cue counts, evaluating B as superior (3 positive cues vs 2). WADD incorporates cue validities, recognizing that the first two cues are substantially more predictive than the last three, thus generally favoring A. By measuring the choice rate for Option A on this specific trial, we obtain a stark contrast: Tallying will yield a rate below 0.5, while WADD will yield a rate above 0.5.

Source:
def metric(data: pd.DataFrame) -> float:
    # Trial 1 directly pits the two most valid features (Option A) 
    # against the three least valid features (Option B).
    # Tallying strictly prefers Option B (tally 3 vs 2).
    # WADD, on average, prefers Option A because the combined validity 
    # of the top 2 features outweighs the bottom 3.
    t1_mask = data['option_a_ratings'].apply(tuple) == (1, 1, 0, 0, 0)
    if not t1_mask.any():
        return 0.5
    
    # Return the proportion of times Option A was chosen
    return float((data.loc[t1_mask, 'response'] == 0).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.2683 (var=0.0392)
- Predicted under pi_2 (simulated): 0.4667 (var=0.0733)
- Observed on real data: 0.4500 (var=0.0206)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    resp = data['response'].values
    
    # Calculate the difference between features
    diff = a_mat - b_mat
    
    # Find the index of the first discriminating cue (first non-zero difference)
    first_diff_idx = np.argmax(np.abs(diff), axis=1)
    
    ttb_preds = np.zeros(len(diff))
    for i in range(len(diff)):
        idx = first_diff_idx[i]
        if diff[i, idx] > 0:
            ttb_preds[i] = 0
        elif diff[i, idx] < 0:
            ttb_preds[i] = 1
        else:
            ttb_preds[i] = 0.5
            
    # Return the proportion of choices that align with the Take-The-Best prediction
    return float(np.mean(resp == ttb_preds))
```

**Observed (real) value:** 0.4883 (var=0.0032)
**Predicted under pi_3:** 0.3554 (var=0.0111)
**Predicted under pi_2:** 0.4183 (var=0.0236)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    matches = 0
    valid_trials = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        ttb_pred = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        if ttb_pred != -1:
            if row['response'] == ttb_pred:
                matches += 1
            valid_trials += 1
    return matches / valid_trials if valid_trials > 0 else 0.5
```

**Observed (real) value:** 0.4963 (var=0.0022)
**Predicted under pi_3:** 0.3056 (var=0.0127)
**Predicted under pi_2:** 0.4096 (var=0.0238)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, the observed metric values hover around 0.45 to 0.50, suggesting that subjects are either guessing, or their choices are orthogonal to the predictions of both Tallying and WADD. However, Tallying (Theory 1) consistently predicts strong deviations from 0.5 (e.g., 0.78 in Exp 1, 0.26 in Exp 2, 0.30 in Exp 4), making it a poor fit for the data. WADD (Theory 2) is closer to the observed data but still predicts some systematic preferences that aren't strongly reflected in the real data. Since Tallying is fundamentally mismatched to the near-random or highly noisy behavior observed, it should be replaced with a completely different theoretical account.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace the Tallying theory with a 'Take-The-Best' (TTB) heuristic or a 'Random Guessing' baseline. Given that the observed data consistently shows metric values near 0.5 for both Tallying-critical and TTB-critical trials, a pure random guessing theory (or a highly constrained limited-attention model where subjects only look at a single random feature) might better explain the lack of systematic preference. Alternatively, propose a strict Take-The-Best model to formally evaluate the lexicographic hypothesis in this domain."
}
```

## Usage

```json
{
  "prompt_token_count": 5357,
  "candidates_token_count": 321,
  "total_token_count": 6805
}
```
