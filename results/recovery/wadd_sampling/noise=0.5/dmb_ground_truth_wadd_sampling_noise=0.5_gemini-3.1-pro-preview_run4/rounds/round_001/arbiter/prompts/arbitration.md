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
Decision-makers use a Non-linear Weighted Additive (WADD) strategy, computing an overall value for each option by summing the exponentiated validities of its positive features. The non-linear scaling of validities allows the strategy to smoothly interpolate between Tallying (treating features equally) and Take The Best (heavily weighting the most valid features).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    a, b = stim[0], stim[1]
    
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    val = np.power(val, gamma)
    
    score_a = np.sum(val * a)
    score_b = np.sum(val * b)
    
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p = e / np.sum(e)
    
    return (1.0 - epsilon) * p + epsilon * np.array([0.5, 0.5])

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))

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
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 5: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 6: A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 7: A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 8: A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 0]

**Rationale:** To quantitatively dissociate the Non-linear Weighted Additive (WADD) strategy from Tallying, this design uses 5 features with a broad spread of validities. Tallying relies purely on the count of strict feature-wise wins, ignoring both the magnitude of the validities and their non-linear scaling. In contrast, WADD computes an overall value by summing exponentiated validities. The trial pairs are constructed to pit the number of winning features against the magnitude of the validities. We include trials where Tallying predicts a clear win for one option (e.g., winning on 3 or 4 lower-validity features) while WADD strongly prefers the other (winning on 1 or 2 high-validity features, especially when gamma > 1). We also include trials where Tallying predicts a perfect tie (equal number of winning features), forcing it to guess, whereas WADD makes a deterministic prediction based on the specific validities of the winning features.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
The experimental design includes several 'tie' trials (trials 4, 5, and 7) where both options have an equal number of winning features. Tallying makes a completely random choice (50% A, 50% B) on these trials, regardless of its noise parameters. However, in these specific trials, option A always possesses the higher-validity features, meaning WADD consistently computes a higher overall value for A and thus predicts choosing A more often than 50%. By measuring the proportion of times subjects choose A on these tally-tied trials, we clearly separate the two theories: Tallying predicts exactly 0.5, while WADD predicts a value significantly greater than 0.5.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd
    
    ties = []
    for a, b in zip(data['option_a_ratings'], data['option_b_ratings']):
        a_w = sum(1 for x, y in zip(a, b) if x > y)
        b_w = sum(1 for x, y in zip(a, b) if y > x)
        ties.append(a_w == b_w)
        
    tie_data = data[ties]
    if len(tie_data) == 0:
        return 0.5
        
    # In tie trials, A is designed to have higher-validity features than B.
    # Tallying predicts 50% A (response == 0) because the tallies are tied.
    # WADD predicts > 50% A because A's WADD score is higher.
    return float(np.mean(tie_data['response'] == 0))

### RESULTS
- Predicted under pi_3 (simulated): 0.8056 (var=0.0141)
- Predicted under pi_2 (simulated): 0.4739 (var=0.0063)
- Observed on real data: 0.5667 (var=0.0123)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.9, 0.6, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 2: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 7: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Rationale:** This design dissociates Tallying from Non-linear Weighted Additive (WADD) models by varying the distribution of feature validities against the sheer count of winning features. Tallying purely counts the number of strictly winning features (ignoring validity magnitudes entirely), whereas WADD sums exponentiated validities. By using a steep drop-off in validities (e.g., two highly valid experts and three lower-validity experts), we can construct trials where Tallying predicts a clear win for the option with more winning features, but WADD predicts the opposite because the fewer features are highly valid. We also include trials where Tallying predicts a perfect tie (equal number of winning features) forcing it to guess, while WADD makes a deterministic prediction. Finally, trials where WADD's prediction flips depending on its non-linearity parameter (gamma) are included to further separate the models.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
Focuses specifically on Trial 1 where Option A has 3 positive features (but lower validities) and Option B has 2 positive features (but highest validities). Tallying will consistently prefer Option A (response 0) because 3 > 2. The WADD model, however, will strongly prefer Option B (response 1) for almost all reasonable values of its non-linearity parameter gamma, because the sum of the heavily weighted top validities dwarfs the sum of the lower validities. Thus, the mean response on this trial provides a highly discriminative, low-variance contrast between the two models.

Source:
def metric(data: pd.DataFrame) -> float:
    # Project option_a_ratings to string for hashability and comparison
    a_str = data['option_a_ratings'].apply(lambda x: ''.join(map(str, (int(v) for v in x))))
    
    # Trial 1 is uniquely identified by Option A having exactly these ratings
    t1_mask = a_str == '00111'
    
    if t1_mask.sum() == 0:
        return 0.0
        
    # Return the proportion of times Option B was chosen on this trial
    return float(data.loc[t1_mask, 'response'].mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.7300 (var=0.0663)
- Predicted under pi_2 (simulated): 0.1400 (var=0.0182)
- Observed on real data: 0.5000 (var=0.0450)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    preds = []
    for i in range(len(data)):
        p = -1
        for j in range(4):
            if a[i, j] > b[i, j]:
                p = 0
                break
            elif b[i, j] > a[i, j]:
                p = 1
                break
        preds.append(p)
        
    preds = np.array(preds)
    return float(np.mean(data['response'] == preds))
```

**Observed (real) value:** 0.4850 (var=0.0051)
**Predicted under pi_3:** 0.4531 (var=0.0128)
**Predicted under pi_2:** 0.2606 (var=0.0039)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a = np.stack(data['option_a_ratings'].values)
    b = np.stack(data['option_b_ratings'].values)
    
    diff = a - b
    # The first index where features differ (since validities are strictly descending)
    first_diff_idx = np.argmax(diff != 0, axis=1)
    ttb_val = diff[np.arange(len(diff)), first_diff_idx]
    ttb_winner = np.where(ttb_val == 1, 0, 1)
    
    a_wins = np.sum(diff == 1, axis=1)
    b_wins = np.sum(diff == -1, axis=1)
    
    valid_mask = (a_wins != b_wins)
    tally_winner = np.where(a_wins > b_wins, 0, 1)
    
    # Focus only on trials where Tallying and Take The Best make strictly opposite predictions
    conflict_mask = valid_mask & (ttb_winner != tally_winner)
    
    if not np.any(conflict_mask):
        return 0.5
        
    responses = data['response'].values
    ttb_matches = np.sum(responses[conflict_mask] == ttb_winner[conflict_mask])
    
    return float(ttb_matches / np.sum(conflict_mask))

```

**Observed (real) value:** 0.3844 (var=0.0082)
**Predicted under pi_3:** 0.3056 (var=0.0217)
**Predicted under pi_2:** 0.1103 (var=0.0071)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, the observed data consistently falls between the predictions of the Non-linear Weighted Additive (WADD) model (THEORY 1) and the Tallying model (THEORY 2), frequently hovering around 0.5 on conflict trials. For instance, in Experiment 2, WADD predicts 0.73, Tallying predicts 0.14, and the observed value is exactly 0.50. Similarly, in Experiment 1, the observed value of 0.56 is between the two extremes. This pattern strongly suggests that neither a pure Tallying nor a pure WADD/Take-The-Best strategy describes the aggregate data well. Instead, the population likely consists of a mixture of strategies (e.g., some subjects using Tallying, others using a validity-weighted strategy), or individuals are using a strategy that dynamically switches between the two based on confidence or feature dispersion.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace the Tallying theory with a 'Strategy Mixture' theory. This new theory should posit that the population is heterogeneous, with a certain probability 'p_ttb' of a subject using Take-The-Best (or a validity-weighted strategy) and '1 - p_ttb' of using Tallying (Equal Weight). Alternatively, it could model a within-subject probabilistic switching between these two heuristics. This would naturally predict the intermediate (~0.5) aggregate values observed across conflict trials in all four experiments, which neither deterministic theory can capture alone."
}
```

## Usage

```json
{
  "prompt_token_count": 5209,
  "candidates_token_count": 349,
  "total_token_count": 6460
}
```
