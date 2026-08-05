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
Take-The-Best (TTB) models decision-making as a non-compensatory, lexicographic process. People search through available features in descending order of their validity (importance) and stop at the first feature that discriminates between the two options. The option with the higher value on this decisive feature is chosen. If no features discriminate, the decision reduces to a guess. Unlike Weighted Additive (WADD) models, TTB does not allow deficits on high-validity cues to be compensated by advantages on lower-validity cues.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort features by validity in descending order (stable sort for ties)
    order = np.argsort(-validities, kind='stable')
    
    a, b = stim[0], stim[1]
    scores = np.zeros(2)
    
    # Lexicographic search: stop at the first discriminating feature
    for idx in order:
        if a[idx] > b[idx]:
            scores[0] = 1.0
            break
        elif b[idx] > a[idx]:
            scores[1] = 1.0
            break
            
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax over the scores (scores are either [1,0], [0,1], or [0,0])
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
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 4: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 5: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Rationale:** To quantitatively dissociate Take-The-Best (TTB) from the Weighted Additive (WADD) model, we construct a 5-feature design with linearly spaced validities. TTB is non-compensatory, meaning the single highest-validity cue that discriminates between the two options will strictly determine its choice, regardless of the values of all other cues. WADD is compensatory and integrates all cue values weighted by their validities, allowing multiple lower-validity cues to override a deficit on the highest-validity cue. The core dissociation trials pit a single advantage on the most predictive available feature against multiple advantages on less predictive features. For instance, in Trial 1, Option A is endorsed only by the highest-validity expert, while Option B is endorsed by the remaining four. TTB decisively chooses A, while WADD decisively chooses B. Trial 4 checks for the same compensatory logic but restricts the highest valid cue to a tie, making the second-highest cue the decisive one for TTB. Trial 6 acts as an agreement trial where both models prefer Option A, ensuring that subjects are paying attention and not just picking the option with more positive ratings.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Calculates the proportion of trials where the subject's choice matches the prediction of the Take-The-Best (TTB) model. TTB sequentially checks features in order of validity and stops at the first discriminating feature. The experimental design contains many trials where the first discriminating feature favors one option, but the sum of the remaining features strongly favors the other. TTB will consistently choose the former, resulting in a metric close to 1.0, whereas WADD will compensate and choose the latter, resulting in a metric much closer to 0.0.

Source:
def metric(data: pd.DataFrame) -> float:
    def ttb_match(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]:
                return row['response'] == 0
            elif b[i] > a[i]:
                return row['response'] == 1
        return False

    return float(data.apply(ttb_match, axis=1).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.8496 (var=0.0075)
- Predicted under pi_2 (simulated): 0.3115 (var=0.0131)
- Observed on real data: 0.6004 (var=0.0022)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 4: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 6: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** To quantitatively dissociate the Weighted Additive (WADD) model from Take-The-Best (TTB), we employ a 5-feature design with linearly descending validities. TTB employs a non-compensatory lexicographic stopping rule, meaning it will always choose the option endorsed by the highest-validity discriminating cue, completely ignoring all other cues. In contrast, WADD is fully compensatory and sums the validity-weighted values of all features. The core dissociation trials pit an option with a single advantage on the most predictive available feature against an option with multiple advantages on less predictive features. For example, when Option A is endorsed only by the highest-validity expert and Option B by all other experts, TTB decisively chooses A, whereas WADD decisively chooses B. We include variations where the highest-validity cue ties (forcing TTB to rely on the second-highest cue while WADD still integrates the rest) and agreement trials to ensure baseline task engagement.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times the subject chooses Option B on trials where Option B has a greater total number of positive features than Option A. In the specified experimental design, these trials correspond to scenarios where Option A is supported by the single most predictive discriminating cue (which Take-The-Best relies on exclusively), while Option B is supported by a larger number of less predictive cues. Consequently, TTB will deterministically choose Option A (yielding a metric value near 0), whereas a compensatory WADD model will aggregate the multiple advantages of Option B and choose it most of the time (yielding a metric value much closer to 1).

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Calculate the total number of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Select trials where Option B has more positive features than Option A
    # In the experimental design (Trials 1, 2, 3, 5), Option A is endorsed by the 
    # single highest-validity discriminating cue, but Option B has a higher sheer 
    # number of lower-validity cues.
    mask = sum_b > sum_a
    
    if not mask.any():
        return 0.5
        
    # Return the proportion of times Option B was chosen (response == 1)
    return float(data.loc[mask, 'response'].mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.1300 (var=0.0100)
- Predicted under pi_2 (simulated): 0.7538 (var=0.0204)
- Observed on real data: 0.4131 (var=0.0041)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    tallying_consistent = 0
    total_dissociation_trials = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        sum_a = np.sum(a)
        sum_b = np.sum(b)
        
        # Identify dissociation trials: one option has more features, but lacks the first (highest validity) feature
        if sum_a > sum_b and a[0] == 0:
            total_dissociation_trials += 1
            if row['response'] == 0:
                tallying_consistent += 1
        elif sum_b > sum_a and b[0] == 0:
            total_dissociation_trials += 1
            if row['response'] == 1:
                tallying_consistent += 1
                
    if total_dissociation_trials == 0:
        return 0.5
        
    return float(tallying_consistent / total_dissociation_trials)
```

**Observed (real) value:** 0.4113 (var=0.0093)
**Predicted under pi_3:** 0.1544 (var=0.0114)
**Predicted under pi_2:** 0.4050 (var=0.0960)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    a_f1 = np.array([a[0] for a in data['option_a_ratings']])
    b_f1 = np.array([b[0] for b in data['option_b_ratings']])
    resp = data['response'].values
    chosen_f1 = np.where(resp == 0, a_f1, b_f1)
    return float(np.mean(chosen_f1))
```

**Observed (real) value:** 0.5900 (var=0.0027)
**Predicted under pi_3:** 0.8462 (var=0.0136)
**Predicted under pi_2:** 0.5321 (var=0.0463)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the four experiments, neither Take-The-Best (pi_3) nor the Weighted Additive model (pi_2) consistently captures the observed data. The observed metrics consistently fall somewhere between the extreme non-compensatory predictions of TTB and the fully compensatory predictions of WADD. Furthermore, the low between-subject variance in the observed data indicates that this intermediate behavior is relatively homogeneous across subjects, rather than a split population of pure TTB users and pure WADD users. WADD comes closer in Experiments 3 and 4, but fails to capture the higher reliance on the most valid cue seen in Experiments 1 and 2. TTB consistently over-predicts reliance on the single best cue. Because both theories fail to capture the robust intermediate behavior, a new theoretical framework is needed.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Mixture of Strategies' (or Probabilistic Strategy Selection) theory, where on any given trial, a subject stochastically chooses to either employ a lexicographic heuristic (like TTB) or a compensatory strategy (like Tallying or WADD). Alternatively, propose a 'Non-linear Cue Weighting' theory where cue validities are transformed via a steep but continuous decay function, allowing the model to act mostly lexicographic but still permitting compensation when a large number of lower-validity cues stack up. This would replace the rigid TTB theory and better capture the intermediate, low-variance subject averages."
}
```

## Usage

```json
{
  "prompt_token_count": 5089,
  "candidates_token_count": 329,
  "total_token_count": 6372
}
```
