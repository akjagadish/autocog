# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_3") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_3" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
People compare two options by consulting cues one at a time in order of validity, stopping at the first cue that discriminates between the two options. That cue alone determines the choice: the option with the higher value on the discriminating cue wins, and no other cue is consulted. Cues with lower validity are never reached when a higher-validity cue already discriminates, so Take The Best is a "one-reason" decision rule — only a single feature is ever used on any given choice. Because only the sign of the comparison on the top discriminating cue matters, TTB ignores both the magnitude of that difference and all information on lower-validity cues, making it maximally frugal in the use of evidence. Cue validities are subjective and can be learned, inferred from instructions, or fixed by task structure. When no cue discriminates (all feature-wise comparisons tie) the learner has no basis for preference and must guess. Response noise enters through a softmax over the binary TTB score (winner = 1, loser = 0) with inverse temperature beta, plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Take The Best (Gigerenzer & Goldstein 1996).
    # Stimulus is the pair of option feature vectors for the current
    # trial: array-like of shape (2, n_features), row 0 = option A,
    # row 1 = option B. Cue cascade: features are consulted in order
    # of descending validity; the first discriminating cue (strict
    # inequality) determines the winner; if no cue discriminates,
    # the model guesses uniformly. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    n_features = stim.shape[1]

    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != n_features:
        raise ValueError(
            f"validities length {val.shape[0]} != n_features {n_features}."
        )
    # Descending validity; argsort is stable so validity ties break
    # toward the earlier feature index.
    cue_order = np.argsort(-val, kind="stable").tolist()

    a, b = stim[0], stim[1]
    winner = None
    for j in cue_order:
        if a[j] > b[j]:
            winner = 0
            break
        if b[j] > a[j]:
            winner = 1
            break

    if winner is None:
        # No discriminating cue — pure guess.
        return np.ones(2) / 2.0

    scores = np.array([1.0, 0.0]) if winner == 0 else np.array([0.0, 1.0])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. For the
    # binary TTB score this collapses to sigmoid(beta) for the winner,
    # giving a direct mapping from beta onto the paper's flip-noise
    # levels (beta=0 ↔ 50/50; beta ≫ 1 ↔ deterministic).
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_3
Weighted Additive (WADD) model with non-linear validity scaling and extended lapse rate: Decision makers evaluate options by computing a weighted sum of their feature values. The weights are formed by centering the cue validities (val - 0.5) and raising their absolute values to a power gamma (preserving sign), which allows the model to interpolate between equal-weighting, proportional weighting, and non-compensatory behavior without extreme log-odds scaling. To account for the high degree of noise or chance-level behavior observed in specific paradigms, the lapse rate (epsilon) can range up to 1.0, and beta down to 0.0, allowing the model to capture completely random guessing natively.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    
    # Center validities so 0.5 gives 0 weight, avoiding discrete parameter
    base_w = val - 0.5
        
    # Signed exponentiation to handle negative base_w with fractional gamma safely
    w = np.sign(base_w) * (np.abs(base_w) ** gamma)
        
    score_a = np.sum(w * a)
    score_b = np.sum(w * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    return (1.0 - epsilon) * p_core + epsilon * 0.5


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=float)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 3: A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 4: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 7: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 8: A=[1, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Rationale:** This design pits Take The Best (TTB) against the Weighted Additive (WADD) model by systematically varying the compensatory evidence from lower-validity cues while keeping the highest-discriminating cue constant. TTB is a non-compensatory, 'one-reason' heuristic: it decides solely based on the highest-validity cue that discriminates between the options, completely ignoring all other cues. Consequently, TTB predicts identical choice probabilities across all trials where the same cue determines the choice. In contrast, WADD computes a weighted sum of all features. By presenting trials where the highest-validity cue favors one option, but an increasing number of lower-validity cues oppose it, WADD predicts a graded change in choice probabilities (even flipping the choice if the gamma parameter allows for compensatory weighting). TTB predicts a completely flat probability profile across these same trials.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Take The Best (TTB) is a non-compensatory heuristic that relies solely on the highest-validity discriminating cue, ignoring all other features. Consequently, TTB predicts identical choice probabilities across all trial pairs, meaning a subject's adherence to TTB should be uniformly high across all pairs (subject only to constant lapse and softmax noise). In contrast, the Weighted Additive (WADD) model integrates all cues, so its confidence fluctuates depending on the degree of cue conflict. On trials where lower-validity cues strongly oppose the best cue, WADD's adherence to the TTB prediction drops significantly. By calculating the minimum TTB adherence across all 8 unique trial pairs for each subject, we capture this localized drop. TTB will maintain a high minimum adherence, whereas WADD will exhibit a much lower minimum due to its compensatory weighting on conflicting trials.

Source:
def metric(data: pd.DataFrame) -> float:
    subject_mins = []
    for subj, subj_df in data.groupby('subject_id'):
        pair_adherence = {}
        for _, row in subj_df.iterrows():
            a = tuple(row['option_a_ratings'])
            b = tuple(row['option_b_ratings'])
            # Use frozenset to group identical trial pairs regardless of A/B presentation order
            pair_key = frozenset({a, b})
            
            # Determine Take The Best (TTB) prediction
            ttb_choice = None
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_choice = 0
                    break
                elif b[i] > a[i]:
                    ttb_choice = 1
                    break
            
            if ttb_choice is None:
                continue
                
            adherence = 1 if row['response'] == ttb_choice else 0
            
            if pair_key not in pair_adherence:
                pair_adherence[pair_key] = []
            pair_adherence[pair_key].append(adherence)
            
        if not pair_adherence:
            continue
            
        # Compute the proportion of TTB adherence for each unique trial pair
        proportions = [sum(advs)/len(advs) for advs in pair_adherence.values()]
        # Take the minimum adherence across all pairs for this subject
        subject_mins.append(min(proportions))
        
    if not subject_mins:
        return 0.0
        
    # Return the average of these minimums across all subjects
    return float(sum(subject_mins) / len(subject_mins))

### RESULTS
- Predicted under pi_1 (simulated): 0.7283 (var=0.0191)
- Predicted under pi_3 (simulated): 0.3333 (var=0.0071)
- Observed on real data: 0.2667 (var=0.0067)

## EXPERIMENT 2 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=9):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 3: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 4: A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 5: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 7: A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  trial 8: A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  trial 9: A=[0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]

**Rationale:** This design quantitatively dissociates the Weighted Additive (WADD) model with non-linear validity scaling from Take The Best (TTB) by systematically varying the amount of compensatory evidence on lower-validity cues while holding the highest-validity discriminating cue constant. TTB is a non-compensatory 'one-reason' heuristic: its choice and predicted choice probability are determined entirely by the first discriminating cue, meaning it predicts a completely flat choice probability profile across any set of trials where the same top cue discriminates. In contrast, WADD integrates all features. By creating a gradient of trials where the highest-validity cue favors Option A but the number of lower-validity cues favoring Option B systematically decreases, WADD predicts a graded, monotonic change in choice probabilities, whereas TTB predicts identical probabilities across the gradient. We repeat this logic for subsets of trials where the first cue is tied and the second cue becomes the highest discriminating cue.

**Computed schedule:** 9 unique pairs × 10 reps = 90 trials per subject.



### METRIC
Rationale:
In this experimental design, the first discriminating cue favors Option A in every single trial. Therefore, Take The Best (TTB) consistently predicts Option A across the entire experiment, resulting in a high overall probability of choosing A (averaging ~85%, constrained only by the lapse rate). In contrast, the Weighted Additive (WADD) model predicts a significantly lower overall proportion of A choices. For high values of gamma (>4), the centered validities shrink to near-zero, causing WADD to predict ~50/50 guessing. For low values of gamma (<2), WADD behaves compensatorily and favors Option B in trials where B has a strong advantage in lower-validity cues (e.g., Trials 1, 2, and 6). Thus, simply measuring the overall proportion of Option A choices provides a robust, large-effect-size discriminator between the two models.

Source:
def metric(data: pd.DataFrame) -> float:
    return float((data['response'] == 0).mean())

### RESULTS
- Predicted under pi_1 (simulated): 0.8229 (var=0.0163)
- Predicted under pi_3 (simulated): 0.5184 (var=0.0034)
- Observed on real data: 0.5000 (var=0.0000)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        ttb_pred = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred is not None:
            matches.append(1 if resp == ttb_pred else 0)
            
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5000 (var=0.0000)
**Predicted under pi_1:** 0.8444 (var=0.0093)
**Predicted under pi_3:** 0.5010 (var=0.0037)

### Experiment 4
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    # Determine which option is favored by the highest validity cue (cue 0)
    cue_0_a = a_ratings[:, 0]
    cue_0_b = b_ratings[:, 0]
    cue_0_winner = (cue_0_b > cue_0_a).astype(int)
    
    # Did the subject choose the option favored by cue 0?
    chose_cue_0 = (data['response'] == cue_0_winner).astype(float)
    
    # Calculate the tally difference in favor of the cue 0 winner
    tally_a = (a_ratings > b_ratings).sum(axis=1)
    tally_b = (b_ratings > a_ratings).sum(axis=1)
    tally_diff = np.where(cue_0_winner == 0, tally_a - tally_b, tally_b - tally_a)
    
    # Compare choice probabilities when tally strongly agrees vs. disagrees/ties with cue 0
    high_diff_mask = tally_diff >= 3
    low_diff_mask = tally_diff <= 0
    
    if not np.any(high_diff_mask) or not np.any(low_diff_mask):
        return 0.0
        
    high_diff_rate = chose_cue_0[high_diff_mask].mean()
    low_diff_rate = chose_cue_0[low_diff_mask].mean()
    
    return float(high_diff_rate - low_diff_rate)

```

**Observed (real) value:** -0.0237 (var=0.0386)
**Predicted under pi_1:** -0.0025 (var=0.0080)
**Predicted under pi_3:** 0.0627 (var=0.0377)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, the observed data perfectly matches pure random guessing. In Experiment 2 and 3, the observed metrics are exactly 0.5000. In Experiment 4, the tally difference effect is approximately 0, meaning cue alignment has no effect on choices. In Experiment 1, the observed minimum adherence of 0.2667 perfectly aligns with the expected minimum of 8 independent Binomial(12, 0.5) distributions. Neither a purely compensatory nor a non-compensatory model is needed; subjects are simply ignoring the features and guessing.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'Random Guessing' theory. The data indicates that subjects completely ignore all feature information and validities, likely due to lack of feedback or motivation, and simply choose between the two options with equal probability on every trial. The model should return a uniform 50/50 prediction regardless of the stimulus."
}
```

## Usage

```json
{
  "prompt_token_count": 6052,
  "candidates_token_count": 224,
  "total_token_count": 10079
}
```
