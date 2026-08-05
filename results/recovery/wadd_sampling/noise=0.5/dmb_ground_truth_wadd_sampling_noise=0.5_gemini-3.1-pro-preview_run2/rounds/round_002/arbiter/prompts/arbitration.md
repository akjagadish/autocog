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
Weighted Additive (WADD) Theory with Non-Linear Cue Scaling: People evaluate multi-attribute options by computing an overall value for each option. This value is determined by taking a weighted sum of the option's features, where the weights correspond to the subjective validities of the respective cues scaled by a non-linear parameter. This scaling allows decision-makers to flexibly upweight highly valid cues (approaching a non-compensatory strategy) or downweight them (approaching an equal-weight tallying strategy). Decision-makers then choose probabilistically between the options by comparing these total weighted scores via a softmax function.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Non-linear scaling of validities
    weights = val ** gamma
    
    a, b = stim[0], stim[1]
    
    # Calculate weighted sums for both options
    score_a = np.sum(weights * a)
    score_b = np.sum(weights * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Numerically stable softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    # Incorporate lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))

## THEORY 2 — pi_4
Hybrid Heuristic Theory: Decision-makers integrate evidence from multiple strategies before making a choice, rather than probabilistically sampling between distinct strategies. Specifically, individuals compute a combined subjective value for each option by taking a weighted average of normalized compensatory (validity-weighted) and non-compensatory (tallying) evidence. A single stochastic decision process then operates on these integrated values.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    n_features = len(val)
    
    # Normalized WADD scores
    sum_val = np.sum(val)
    score_wadd_a = np.sum(val * a) / sum_val
    score_wadd_b = np.sum(val * b) / sum_val
    
    # Normalized Tallying scores
    score_tal_a = float(np.sum(a > b)) / n_features
    score_tal_b = float(np.sum(b > a)) / n_features
    
    beta = float(parameters["beta"])
    w_mix = float(parameters["w_mix"])
    epsilon = float(parameters["epsilon"])
    
    # Combined integrated scores
    score_combined_a = w_mix * score_wadd_a + (1.0 - w_mix) * score_tal_a
    score_combined_b = w_mix * score_wadd_b + (1.0 - w_mix) * score_tal_b
    scores = np.array([score_combined_a, score_combined_b])
    
    # Single Softmax
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    # Lapse rate
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.65, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 3: A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 4: A=[0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 8: A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]

**Rationale:** The design sharply dissociates the Advocated Weighted Additive (WADD) theory with Non-Linear Cue Scaling from the Competing Hybrid Heuristic Theory. The Hybrid Theory assumes a linear combination of normalized WADD (linear) and Tallying scores. Thus, if both linear WADD and Tallying agree on an option, the Hybrid model is mathematically constrained to strongly prefer that option, regardless of its mixing parameter. However, the Advocated WADD theory uses a non-linear scaling parameter (gamma) on validities. For gamma > 1, it heavily upweights the most valid cues, and for gamma < 1, it approaches equal weighting. We exploit this by designing 'Trap Trials' where linear WADD and Tallying both point to Option B (so Hybrid must choose B), but the non-linear scaling of WADD points to Option A (because Option A possesses the single most valid cue, overcoming the sum of lower validities). We also include 'Contradiction Trials' where linear WADD and Tallying oppose each other, ensuring the Hybrid model's mixing parameter can be properly identified, making the test strictly fair and highly diagnostic.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of trials where the subject chose the option that LACKS the single most valid cue. The experimental design is structured such that the option without the most valid cue almost always has a higher tally of total cues and a higher linear WADD score. Consequently, the Hybrid model (which mixes linear WADD and Tallying) is mathematically constrained to frequently choose the option without the most valid cue, resulting in a high metric value. In contrast, the Advocated theory (WADD with Non-Linear Cue Scaling) uses a gamma parameter that, for gamma > 1, heavily upweights the most valid cue, leading it to consistently choose the option possessing it. Because the parameter space for gamma is predominantly > 1, the Advocated model will yield a significantly lower metric value on average.

Source:
def metric(data: pd.DataFrame) -> float:
    # a_cue_0 is 1 if option A has the most valid cue, 0 otherwise.
    a_cue_0 = data['option_a_ratings'].apply(lambda x: x[0])
    # response is 0 if A was chosen, 1 if B was chosen.
    # If response == a_cue_0, the subject chose the option that LACKS the most valid cue.
    # For example, if A has it (1) and they chose B (1), they chose the option without it.
    # If A lacks it (0) and they chose A (0), they chose the option without it.
    return float((data['response'] == a_cue_0).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.3456 (var=0.0583)
- Predicted under pi_4 (simulated): 0.7350 (var=0.0125)
- Observed on real data: 0.5792 (var=0.0095)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 8: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Rationale:** To cleanly dissociate the Advocated Hybrid Heuristic Theory from the Competing Weighted Additive (WADD) Theory with Non-Linear Cue Scaling, we exploit the functional form of their effective cue weights. The Hybrid theory assumes a linear combination of normalized WADD (which is linear in validity) and Tallying (which applies a uniform weight to all features). Consequently, the Hybrid model's effective weights are always strictly linear with respect to cue validities. In contrast, the Competing WADD theory scales validities by an exponent (gamma), producing weights that are convex (gamma > 1) or concave (gamma < 1) with respect to validity. We use 5 features with linearly spaced validities to test this. For example, in trials where the sum of validities is equal (e.g., cues 1 and 4 vs. cues 2 and 3), the Hybrid model perfectly ties regardless of its mixing parameter, whereas the Non-Linear WADD model will predictably diverge from a tie depending on its gamma parameter. By including a mix of these 'linear-tie' trials alongside classical Tallying vs. linear WADD contradictions, we can perfectly isolate the linear interpolation of the Hybrid model from the non-linear scaling of the Competing model.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
In the advocated Hybrid theory, the effective weights of the cues are strictly linear with respect to their validities. Thus, for trials where the sum of validities of the present cues is equal for both options (Trials 1 and 5), the Hybrid model predicts an exact tie (P(Choose A) = 0.5) regardless of the mixing parameter or softmax temperature. In contrast, the competing WADD theory applies a non-linear scaling (gamma) to the validities. Because x^gamma is strictly convex or concave for gamma != 1, the scaled sums will diverge from a tie, pushing the choice probability away from 0.5. This metric computes the absolute deviation of the choice probability from 0.5 on these specific linear-tie trials. It will be near 0 (modulo sampling noise) for the Hybrid model, but significantly larger for the WADD model.

Source:
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    import numpy as np
    
    # Convert rating lists to string representations to identify specific trials
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Identify the 'linear-tie' trials
    # Trial 1: Cues 1 & 4 vs Cues 2 & 3 (sum of validities = 1.5 for both)
    mask_t1 = (data['A_str'] == '10010') & (data['B_str'] == '01100')
    # Trial 5: Cues 2 & 4 vs Cues 1 & 5 (sum of validities = 1.4 for both)
    mask_t5 = (data['A_str'] == '01010') & (data['B_str'] == '10001')
    
    dev = 0.0
    if mask_t1.sum() > 0:
        p_A_t1 = (data.loc[mask_t1, 'response'] == 0).mean()
        dev += abs(p_A_t1 - 0.5)
        
    if mask_t5.sum() > 0:
        p_A_t5 = (data.loc[mask_t5, 'response'] == 0).mean()
        dev += abs(p_A_t5 - 0.5)
        
    return float(dev)

### RESULTS
- Predicted under pi_3 (simulated): 0.2750 (var=0.0441)
- Predicted under pi_4 (simulated): 0.0333 (var=0.0252)
- Observed on real data: 0.0167 (var=0.0257)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    responses = data['response'].values
    
    # The validities are monotonically decreasing from left to right.
    # Thus, Take The Best (TTB) will choose based on the first feature
    # (from index 0 to 4) that discriminates between A and B.
    diff = a_ratings - b_ratings
    
    # Find the index of the first discriminating cue (where difference is non-zero)
    first_diff_idx = (diff != 0).argmax(axis=1)
    
    # Extract the difference value at that first discriminating cue
    first_diff_val = np.take_along_axis(diff, first_diff_idx[:, None], axis=1).squeeze()
    
    # If first_diff_val > 0 (A has the feature, B does not), TTB predicts A (response 0).
    # If first_diff_val < 0 (B has the feature, A does not), TTB predicts B (response 1).
    ttb_predictions = (first_diff_val < 0).astype(int)
    
    # Return the proportion of choices that match the TTB prediction.
    return float(np.mean(responses == ttb_predictions))
```

**Observed (real) value:** 0.4167 (var=0.0087)
**Predicted under pi_3:** 0.4692 (var=0.0436)
**Predicted under pi_4:** 0.2250 (var=0.0140)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    diff = a_sums - b_sums
    mask = diff != 0
    
    if not mask.any():
        return 0.5
        
    tallying_pred = (diff < 0).astype(int)
    accuracy = (data.loc[mask, 'response'] == tallying_pred[mask]).mean()
    
    return float(accuracy)
```

**Observed (real) value:** 0.6044 (var=0.0126)
**Predicted under pi_3:** 0.7206 (var=0.0372)
**Predicted under pi_4:** 0.7922 (var=0.0109)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import pandas as pd
    
    # Calculate the total number of positive features for each option
    sum_a = data['option_a_ratings'].apply(sum)
    sum_b = data['option_b_ratings'].apply(sum)
    
    # Identify trials where Tallying sees a tie (equal number of features)
    tied_trials = sum_a == sum_b
    
    if tied_trials.sum() == 0:
        return 0.5
        
    # Calculate the proportion of times Option A was chosen in these tied trials
    # (Response 0 means Option A was chosen)
    prob_a_chosen = (data.loc[tied_trials, 'response'] == 0).mean()
    
    return float(prob_a_chosen)
```

**Observed (real) value:** 0.5611 (var=0.0131)
**Predicted under pi_3:** 0.8378 (var=0.0112)
**Predicted under pi_4:** 0.5689 (var=0.0136)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Create a string representation of option A's features to identify trials safely
    data['A_str'] = data['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    
    # Trial 4: A=[1, 1, 0, 0, 0] vs B=[0, 0, 1, 1, 1]
    p_a_t4 = 1.0 - data.loc[data['A_str'] == '11000', 'response'].mean()
    
    # Trial 5: A=[1, 0, 0, 1, 1] vs B=[0, 1, 1, 0, 0]
    p_a_t5 = 1.0 - data.loc[data['A_str'] == '10011', 'response'].mean()
    
    # Return the sum of probabilities of choosing A in these two trials
    return float(p_a_t4 + p_a_t5)
```

**Observed (real) value:** 1.0350 (var=0.0694)
**Predicted under pi_3:** 1.4888 (var=0.0953)
**Predicted under pi_4:** 1.0550 (var=0.0349)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the six experiments, neither theory perfectly captures all the observed data, but Theory 2 (Hybrid Heuristic Theory) shows remarkably precise predictions on Experiments 2, 5, and 6. However, it significantly underestimates the Take-The-Best (TTB) match in Experiment 3 and overestimates the Tallying match in Experiments 1 and 4. Theory 1 (WADD with Non-Linear Scaling), on the other hand, is closer on Experiments 3 and 4 but fails drastically on Experiments 2, 5, and 6. Because Theory 2 accurately captures the linear-tie behavior (Exp 2) and tied-tallying behavior (Exp 5), its core mechanism of linear evidence integration is highly compelling for certain contexts, but it lacks the flexibility to account for trial-by-trial strategy shifts that might be driving the intermediate observed values in Exps 1, 3, and 4. Theory 1's non-linear scaling approach appears fundamentally mismatched to the data in linear-tie scenarios. Therefore, Theory 1 should be completely replaced with a new theory that can bridge the gap.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Probabilistic Strategy Selection' theory. Unlike the Hybrid theory (which integrates normalized scores from different strategies into a single value before choice), this new theory should posit that decision-makers maintain a repertoire of distinct heuristics (e.g., Take-The-Best, Tallying, and linear WADD). On any given trial, a decision-maker probabilistically samples one strategy from this repertoire (governed by a set of base-rate probabilities or strategy weights) and executes it purely. This trial-by-trial or subject-by-subject mixture of discrete strategies can naturally produce the intermediate aggregate choice proportions observed in Experiments 1, 3, and 4, while still allowing for the exact ties in specific stimulus configurations (Experiments 2 and 5) if the sampled strategies themselves predict ties."
}
```

## Usage

```json
{
  "prompt_token_count": 6741,
  "candidates_token_count": 442,
  "total_token_count": 8114
}
```
