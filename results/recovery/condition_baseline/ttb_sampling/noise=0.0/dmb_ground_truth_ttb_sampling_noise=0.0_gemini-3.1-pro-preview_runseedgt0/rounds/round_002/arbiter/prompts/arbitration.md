# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_4") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_4" (THEORY 2 below). Justify your choice.


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


## THEORY 2 — pi_4
Probabilistic Take The Best (Plackett-Luce Cue Search) with High Determinism

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    gamma = float(parameters["gamma"])
    epsilon = float(parameters["epsilon"])
    
    # Identify which cues discriminate and in which direction
    diff = a - b
    favor_a = (diff > 0)
    favor_b = (diff < 0)
    discriminating = favor_a | favor_b
    
    if not np.any(discriminating):
        # No cues discriminate, guess uniformly
        p_a = 0.5
    else:
        # The probability that a given discriminating cue is encountered first 
        # under a Plackett-Luce search order depends only on the relative weights 
        # of the discriminating cues.
        # Subtract max validity for numerical stability before exponentiation.
        max_val = np.max(val[discriminating])
        w = np.exp(gamma * (val - max_val))
        
        weight_a = np.sum(w[favor_a])
        weight_b = np.sum(w[favor_b])
        
        total_weight = weight_a + weight_b
        p_a = weight_a / total_weight
        
    p_core = np.array([p_a, 1.0 - p_a])
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 3: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 4: A=[1, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1]
  trial 5: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Rationale:** To quantitatively dissociate deterministic Take The Best (TTB) from Probabilistic Take The Best (Plackett-Luce Cue Search), we use a 5-feature design with spaced validities. TTB assumes a strict lexicographic stopping rule where the choice is entirely determined by the single highest-validity discriminating cue, meaning the number of lower-validity cues favoring the opposite option should have zero effect on choice probabilities. In contrast, Probabilistic TTB models cue search as a Plackett-Luce process where the probability of encountering a cue first is proportional to its exponentiated validity. Consequently, Probabilistic TTB predicts that adding more lower-validity cues favoring the opposing option will cumulatively draw choice probability away from the option favored by the best cue. By comparing trials where the best cue faces off against a single lower-validity cue versus trials where it faces off against multiple lower-validity cues, we can sharply distinguish TTB's invariant choice probabilities from Probabilistic TTB's sensitivity to the number of opposing cues.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
Probabilistic Take The Best (Prob TTB) models cue search via a Plackett-Luce process. However, because its gamma parameter is uniformly sampled up to 100, about 80% of Prob TTB subjects behave almost deterministically, ignoring lower-validity cues. This causes metrics based on the population mean to fail, as the large majority of subjects show no difference between the two theories. However, the ~20% of Prob TTB subjects with a low gamma parameter will exhibit a strong positive correlation between the number of opposing cues favoring Option B and their likelihood of choosing Option B. Deterministic TTB, on the other hand, predicts a correlation of exactly zero (in expectation) for all subjects, regardless of noise levels. To isolate this distinct sub-population, this metric computes the subject-level Pearson correlation and returns the 90th percentile across the pooled sample. This non-linear aggregation captures the heavy right tail of the Prob TTB distribution, producing a massive point estimate gap, while maintaining the tight between-subject variance of the raw correlations.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    corrs = []
    # Calculate the correlation between opposing cues and choice for each subject
    for subj, subj_data in data.groupby('subject_id'):
        a_matrix = np.vstack(subj_data['option_a_ratings'].values)
        b_matrix = np.vstack(subj_data['option_b_ratings'].values)
        
        # Count how many cues strictly favor Option B over Option A
        favor_b = np.sum(b_matrix > a_matrix, axis=1)
        resp = subj_data['response'].values
        
        # Only compute correlation if there is variance in the responses
        if np.std(favor_b) > 1e-5 and np.std(resp) > 1e-5:
            r = np.corrcoef(favor_b, resp)[0, 1]
            corrs.append(r)
        else:
            corrs.append(0.0)
            
    if len(corrs) == 0:
        return 0.0
        
    # For a single subject's slice, this returns their individual correlation.
    # For the pooled dataframe, this returns the 90th percentile across all subjects,
    # specifically isolating the heavy right tail of Probabilistic TTB subjects.
    return float(np.percentile(corrs, 90))

### RESULTS
- Predicted under pi_1 (simulated): 0.0845 (var=0.0071)
- Predicted under pi_4 (simulated): 0.1753 (var=0.0117)
- Observed on real data: 0.2175 (var=0.0136)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=6):** [0.95, 0.9, 0.85, 0.8, 0.75, 0.7]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0]
  trial 4: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  trial 5: A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  trial 6: A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  trial 7: A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]

**Rationale:** To quantitatively dissociate Probabilistic Take The Best (Plackett-Luce Cue Search) from deterministic Take The Best (TTB), we use a 6-feature design with a linear spread of validities. Deterministic TTB assumes a strict lexicographic stopping rule where the choice is entirely determined by the single highest-validity discriminating cue. Thus, TTB predicts that the probability of choosing the option favored by the best cue remains constant, regardless of how many lower-validity cues favor the opposing option. In contrast, Probabilistic TTB models cue search as a Plackett-Luce process where the probability of encountering a cue first is proportional to its exponentiated validity. Consequently, Probabilistic TTB predicts that adding more lower-validity cues favoring the opposing option will cumulatively draw choice probability away from the option favored by the best cue. By comparing trials where the best cue faces off against a single lower-validity cue versus trials where it faces off against an increasing number of lower-validity cues, we can sharply distinguish TTB's invariant choice probabilities from Probabilistic TTB's sensitivity to the aggregate weight of opposing cues.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
By partitioning trials into those where the TTB-favored option faces exactly 1 opposing cue (Trials 1, 5, 7) versus 3 or more opposing cues (Trials 3, 4, 6), we create a sharp contrast between the two models. Deterministic TTB bases its decision solely on the single best cue, making it entirely blind to the number of opposing cues; thus, it predicts an expected difference of exactly 0 between these two trial sets. Probabilistic TTB samples cues proportionally to their exponentiated validities, meaning that encountering 3+ opposing cues cumulatively draws choice probability away from the TTB winner. This metric yields a strictly positive difference under Probabilistic TTB and effectively minimizes binomial sampling noise by pooling 36 trials per subject for each condition.

Source:
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    data['B_str'] = data['option_b_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    # Low opposing cues (1 cue): Trials 1, 5, 7
    low_mask = (
        ((data['A_str'] == '100000') & (data['B_str'] == '010000')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001000')) |
        ((data['A_str'] == '000001') & (data['B_str'] == '100000'))
    )
    
    # High opposing cues (>= 3 cues): Trials 3, 4, 6
    high_mask = (
        ((data['A_str'] == '100000') & (data['B_str'] == '011100')) |
        ((data['A_str'] == '100000') & (data['B_str'] == '011111')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001111'))
    )
    
    # Determine if the choice was consistent with the TTB winner
    data['ttb_correct'] = 0
    
    # TTB Winner is A for Trials 1, 3, 4, 5, 6
    a_winners = (
        ((data['A_str'] == '100000') & (data['B_str'] == '010000')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001000')) |
        ((data['A_str'] == '100000') & (data['B_str'] == '011100')) |
        ((data['A_str'] == '100000') & (data['B_str'] == '011111')) |
        ((data['A_str'] == '010000') & (data['B_str'] == '001111'))
    )
    data.loc[a_winners & (data['response'] == 0), 'ttb_correct'] = 1
    
    # TTB Winner is B for Trial 7
    b_winners = (
        ((data['A_str'] == '000001') & (data['B_str'] == '100000'))
    )
    data.loc[b_winners & (data['response'] == 1), 'ttb_correct'] = 1
    
    p_low = data.loc[low_mask, 'ttb_correct'].mean()
    p_high = data.loc[high_mask, 'ttb_correct'].mean()
    
    if pd.isna(p_low): p_low = 0.0
    if pd.isna(p_high): p_high = 0.0
    
    return float(p_low - p_high)

### RESULTS
- Predicted under pi_1 (simulated): 0.0061 (var=0.0092)
- Predicted under pi_4 (simulated): 0.1078 (var=0.0169)
- Observed on real data: -0.0178 (var=0.0076)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    agreements = 0
    total = 0
    for a, b, resp in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        ttb_winner = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_winner = 0
                break
            elif b[i] > a[i]:
                ttb_winner = 1
                break
        
        if ttb_winner is not None:
            if resp == ttb_winner:
                agreements += 1
            total += 1
            
    return float(agreements / total) if total > 0 else 0.0
```

**Observed (real) value:** 0.8492 (var=0.0099)
**Predicted under pi_1:** 0.8342 (var=0.0101)
**Predicted under pi_4:** 0.8898 (var=0.0223)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]

**Metric**
```python
import pandas as pd
import numpy as np

def metric(data: pd.DataFrame) -> float:
    matches = 0
    total = 0
    for a, b, resp in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        a_wins = sum(1 for x, y in zip(a, b) if x > y)
        b_wins = sum(1 for x, y in zip(a, b) if y > x)
        if a_wins > b_wins:
            matches += (resp == 0)
            total += 1
        elif b_wins > a_wins:
            matches += (resp == 1)
            total += 1
    return float(matches / total) if total > 0 else 0.5

```

**Observed (real) value:** 0.1739 (var=0.0108)
**Predicted under pi_1:** 0.1358 (var=0.0099)
**Predicted under pi_4:** 0.1175 (var=0.0157)

### Experiment 5
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    resp = data['response'].values
    
    diff = a_ratings - b_ratings
    is_diff = diff != 0
    has_diff = is_diff.any(axis=1)
    
    first_diff_idx = is_diff.argmax(axis=1)
    first_diff_val = diff[np.arange(len(diff)), first_diff_idx]
    
    ttb_pred = np.where(first_diff_val > 0, 0, 1)
    
    match = (resp[has_diff] == ttb_pred[has_diff])
    return float(match.mean()) if len(match) > 0 else 0.5
```

**Observed (real) value:** 0.8400 (var=0.0088)
**Predicted under pi_1:** 0.8827 (var=0.0091)
**Predicted under pi_4:** 0.6515 (var=0.0150)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # TTB always chooses Option A (response = 0) across all 8 trials in this design
    # because A always has the single best discriminating cue. 
    # WADD, by contrast, integrates all cues and will frequently choose Option B 
    # (response = 1) because the sum of lower-validity cues often outweighs the single best cue.
    return float(data['response'].mean())
```

**Observed (real) value:** 0.1613 (var=0.0125)
**Predicted under pi_1:** 0.1537 (var=0.0066)
**Predicted under pi_4:** 0.2587 (var=0.0203)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the six experiments, Theory 1 (Deterministic Take-The-Best) consistently outperforms Theory 2 (Probabilistic TTB / Plackett-Luce Cue Search). In Experiment 2, the observed difference in choice probabilities when the best cue faces 1 vs. 3+ opposing cues is nearly zero (-0.0178), which perfectly matches Theory 1's prediction (0.0061) and strongly violates Theory 2's prediction (0.1078). Theory 1 also accurately captures the high rates of TTB-consistent choices in Experiments 3, 5, and 6. Theory 2 systematically overpredicts the influence of lower-validity opposing cues on the average subject. While Theory 2 slightly better captured the heavy right tail of correlations in Experiment 1, it fails to capture the population-level insensitivity to opposing cues. Theory 2 is fundamentally misaligned with the aggregate data and should be replaced.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a brand-new theory that serves as a stronger competitor to deterministic TTB. Since the data shows strong lexicographic behavior but with some noise and slight deviations, consider a 'Take-Two' or 'Confirmatory Search' heuristic: subjects consult the most valid cue, but before deciding, they check the second most valid cue to confirm. If the top two cues conflict, they either guess or integrate them. Alternatively, propose a Sequential Sampling / Evidence Accumulation model where cues are processed in order of validity and their values are added to a decision accumulator until a fixed confidence bound is reached."
}
```

## Usage

```json
{
  "prompt_token_count": 7402,
  "candidates_token_count": 362,
  "total_token_count": 9097
}
```
