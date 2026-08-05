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
Take The Best (TTB) is a lexicographic, non-compensatory heuristic. Decision-makers evaluate options by comparing them sequentially on features, starting with the cue that has the highest subjective validity. The first feature that discriminates between the options determines the choice. If all features tie, the decision-maker guesses. Response noise is modeled as an independent lapse rate that occasionally results in a random choice.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Sort features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    a, b = stim[0], stim[1]
    p_core = np.array([0.5, 0.5])  # Default to guessing if all features tie
    
    # Sequential comparison
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    n_opts = p_core.shape[0]
    
    # Blend deterministic TTB choice with uniform lapse
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## THEORY 2 — pi_4
Rank-Dependent Weighting posits that decision-makers assign subjective weights to features based on their validity rank rather than their raw validity values. A power-law decay provides a softer drop-off than an exponential one, better capturing nuanced partial-compensatory behavior. Expanding the maximum inverse temperature (beta) and decay rate (gamma) allows the model to flexibly capture highly deterministic, non-compensatory behavior as well as more graded, compensatory integration.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
        
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Determine the rank of each feature (0 for highest validity)
    order = np.argsort(-validities)
    ranks = np.empty_like(validities)
    ranks[order] = np.arange(len(validities))
    
    # Calculate rank-dependent weights with power-law decay
    gamma = float(parameters["gamma"])
    weights = 1.0 / ((ranks + 1.0) ** gamma)
    
    # Calculate scores for each option
    scores = stim @ weights
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    # Blend with uniform lapse rate
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=6):** [0.95, 0.85, 0.75, 0.65, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  trial 2: A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  trial 3: A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  trial 4: A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  trial 5: A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  trial 6: A=[0, 1, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  trial 7: A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  trial 8: A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]

**Rationale:** This design aims to dissociate the purely lexicographic Take The Best (TTB) heuristic from the Rank-Dependent Weighting (RDW) model by pitting the single highest-validity discriminating feature against a coalition of multiple lower-validity features. TTB strictly relies on the first discriminating feature regardless of how many lower-ranked features oppose it, predicting identical choice probabilities across all trials where the same top feature discriminates. In contrast, RDW integrates all features according to a power-law decay of their ranks. Unless RDW's decay parameter (gamma) is pushed to its extreme upper bound (effectively collapsing it into TTB), RDW predicts varying choice probabilities depending on the number and ranks of the opposing features. By systematically varying the size and rank-composition of the opposing feature coalition, we can quantitatively test whether choices exhibit the strict invariance predicted by TTB or the graded compensation predicted by RDW.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
By design, across all trials, Option A possesses the single highest-validity discriminating feature, meaning TTB will invariably choose Option A (yielding a metric near 1.0, minus lapse rate). However, in a subset of these trials, Option B possesses a greater total number of positive features. RDW's compensatory nature means it will often select Option B in these specific trials due to the aggregated weight of its numerous lower-ranked features. Isolating these exact trials and computing the rate at which Option A is chosen maximizes the contrast between the non-compensatory lexicographic predictions of TTB and the compensatory integration of RDW.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Calculate the number of positive features for each option
    a_sums = data['option_a_ratings'].apply(sum)
    b_sums = data['option_b_ratings'].apply(sum)
    
    # Isolate trials where option B has strictly more positive features than option A
    mask = b_sums > a_sums
    if not mask.any():
        return 0.5
        
    # Return the proportion of times Option A was chosen (response == 0) on these specific trials.
    # TTB consistently chooses A on these trials because A possesses the single highest-validity discriminating feature.
    # RDW will often choose B because B's sheer number of features compensates for lacking the top feature.
    return float(np.mean(data.loc[mask, 'response'] == 0))

### RESULTS
- Predicted under pi_3 (simulated): 0.7922 (var=0.0245)
- Predicted under pi_4 (simulated): 0.5869 (var=0.0343)
- Observed on real data: 0.6839 (var=0.0044)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 4: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  trial 5: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 6: A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 7: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 8: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Rationale:** This design dissociates Rank-Dependent Weighting (RDW) from Take The Best (TTB). TTB strictly follows the highest-validity discriminating feature, entirely ignoring the number or validities of lower-ranked cues. In contrast, RDW integrates all features, weighting them by a power-law decay of their rank. By consistently pitting the highest-ranked discriminating feature (favoring Option A) against coalitions of lower-ranked features of varying sizes (favoring Option B), we can test whether choices are purely non-compensatory (TTB) or exhibit graded, rank-based compensation (RDW).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
By taking the standard deviation of the proportion of B choices across the 8 trial types, we capture the sensitivity of the model to the varying sizes of feature coalitions. TTB evaluates all 8 trial types identically (always favoring A on the first discriminating cue) and thus the standard deviation across trial types will only reflect binomial lapse noise. RDW, being compensatory, will produce genuinely different choice probabilities across the trials depending on how many lower-ranked cues favor B. Using the standard deviation rather than variance linearizes the metric, which helps stabilize the between-subject variance and improves the t-test contrast.

Source:
def metric(data: pd.DataFrame) -> float:
    a_str = data['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    b_str = data['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    trial_id = a_str + "_" + b_str
    
    trial_means = data.groupby(trial_id)['response'].mean()
    if len(trial_means) < 2:
        return 0.0
    return float(trial_means.std(ddof=0))

### RESULTS
- Predicted under pi_3 (simulated): 0.0128 (var=0.0018)
- Predicted under pi_4 (simulated): 0.1222 (var=0.0038)
- Observed on real data: 0.0176 (var=0.0014)

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
**Predicted under pi_3:** 0.2437 (var=0.0293)
**Predicted under pi_4:** 0.2112 (var=0.0478)

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
**Predicted under pi_3:** 0.2250 (var=0.0228)
**Predicted under pi_4:** 0.1800 (var=0.0345)

### Experiment 5
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
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
```

**Observed (real) value:** 0.7133 (var=0.0245)
**Predicted under pi_3:** 0.7650 (var=0.0277)
**Predicted under pi_4:** 0.7867 (var=0.0578)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Metric**
```python
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
```

**Observed (real) value:** 0.6695 (var=0.0161)
**Predicted under pi_3:** 0.7800 (var=0.0231)
**Predicted under pi_4:** 0.8232 (var=0.0257)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_match = 0
    total = 0
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        
        # Features are pre-sorted by validity in descending order based on the design.
        # TTB evaluates features sequentially.
        ttb_pred = -1
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
        
        if ttb_pred == resp:
            ttb_match += 1
        total += 1
        
    return float(ttb_match / total) if total > 0 else 0.0
```

**Observed (real) value:** 0.6896 (var=0.0029)
**Predicted under pi_3:** 0.7556 (var=0.0186)
**Predicted under pi_4:** 0.6908 (var=0.0426)

### Experiment 8
**Design**
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    w = np.array([0.95, 0.75, 0.65, 0.55, 0.5])
    
    def wadd_choice(row):
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        score_a = np.dot(a, w)
        score_b = np.dot(b, w)
        return 0 if score_a > score_b else 1
        
    predicted = data.apply(wadd_choice, axis=1)
    return np.mean(data['response'] == predicted)

```

**Observed (real) value:** 0.3234 (var=0.0041)
**Predicted under pi_3:** 0.2371 (var=0.0204)
**Predicted under pi_4:** 0.3623 (var=0.0428)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, neither Theory 1 (Take The Best, pi_3) nor Theory 2 (Rank-Dependent Weighting, pi_4) perfectly captures the observed data. In Experiment 2, the extremely low standard deviation of choice proportions (0.0176) strongly aligns with the non-compensatory predictions of TTB (0.0128) and directly contradicts the graded compensatory integration of RDW (0.1222). However, in Experiment 1, the observed choice rate (0.6839) sits between TTB's prediction (0.7922) and RDW's prediction (0.5869), suggesting that subjects are more compensatory than pure TTB but less than RDW. Similarly, performance on Experiments 3-8 is mixed, with TTB better capturing some datasets and RDW better capturing others. This pattern strongly suggests a mixture of strategies or a probabilistic thresholding mechanism rather than a single pure strategy.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Strategy Mixture' or 'Dual-Process' theory. This theory should posit that decision-makers probabilistically alternate between a strict non-compensatory heuristic (like Take The Best) and a simple compensatory strategy (like Tallying or WADD) either across trials or across the population. A mixture parameter (alpha) would determine the weight of the TTB vs. Compensatory strategy. This will allow the model to capture the non-compensatory invariance seen in Experiment 2 (by heavily weighting TTB) while still allowing for the partial compensatory pull observed in Experiment 1 and others."
}
```

## Usage

```json
{
  "prompt_token_count": 7249,
  "candidates_token_count": 370,
  "total_token_count": 8638
}
```
