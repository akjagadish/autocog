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
Probabilistic Cue Sampling with Softmax Validities: Decision-makers evaluate options by sampling a single feature on each trial. The probability of sampling a feature is determined by a softmax function over the objective validities scaled by a sensitivity parameter gamma. The option that is superior on the sampled feature is chosen; ties result in guessing. This predicts intermediate choice proportions when validities are mixed, avoiding deterministic winner-takes-all behavior.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")

    validities = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    epsilon = float(parameters["epsilon"])

    # Compute subjective validities using softmax for sampling probabilities
    z = gamma * validities
    z = z - np.max(z)  # numerical stability
    e = np.exp(z)
    p_feat = e / np.sum(e)

    a, b = stim[0], stim[1]

    # Identify wins and ties for each feature
    a_wins = (a > b).astype(float)
    b_wins = (b > a).astype(float)
    ties = (a == b).astype(float)

    # Analytically marginalize over the sampled feature:
    # P(Choose A) = sum_i P(sample i) * P(Choose A | sample i)
    # P(Choose A | sample i) = 1 if a_i > b_i, 0 if b_i > a_i, 0.5 if a_i == b_i
    p_A = np.sum(p_feat * (a_wins + 0.5 * ties))
    p_B = np.sum(p_feat * (b_wins + 0.5 * ties))

    p_core = np.array([p_A, p_B])

    # Apply uniform lapse rate
    return (1.0 - epsilon) * p_core + epsilon * np.array([0.5, 0.5])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## THEORY 2 — pi_4
Stochastic Take-The-Best (Lexicographic): Decision-makers search through features sequentially in descending order of their objective validities. The process is stochastic: at each step, the decision-maker may prematurely terminate the search and guess. If they evaluate a cue and it discriminates between the options, they choose the superior option with high probability, but may choose the inferior option due to execution error or misperception. If the cue does not discriminate, the search continues to the next most valid cue. This algorithmic mechanism generates high stochasticity and intermediate choice proportions without relying on compensatory weighted sums.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")

    validities = np.asarray(parameters["validities"], dtype=float)
    p_stop = float(parameters["p_stop"])
    p_error = float(parameters["p_error"])
    
    # Sort features by validity in descending order
    # Using mergesort for stable sorting in case of tied validities
    order = np.argsort(validities, kind='mergesort')[::-1]
    
    p_A = 0.0
    p_B = 0.0
    p_guess = 0.0
    
    reach_prob = 1.0
    
    for idx in order:
        # At each step, there is a probability of prematurely terminating the search and guessing
        prob_stop_here = reach_prob * p_stop
        p_guess += prob_stop_here
        reach_prob -= prob_stop_here
        
        a_val = stim[0, idx]
        b_val = stim[1, idx]
        
        if a_val > b_val:
            # Cue discriminates in favor of A
            p_A += reach_prob * (1.0 - p_error)
            p_B += reach_prob * p_error
            reach_prob = 0.0
            break
        elif b_val > a_val:
            # Cue discriminates in favor of B
            p_B += reach_prob * (1.0 - p_error)
            p_A += reach_prob * p_error
            reach_prob = 0.0
            break
        else:
            # Cue does not discriminate (tie), continue search
            pass
            
    # If search completes and no cue discriminated, guess
    p_guess += reach_prob
    
    # Distribute guessing probability equally
    p_A += p_guess * 0.5
    p_B += p_guess * 0.5
    
    return np.array([p_A, p_B])


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


## EXPERIMENT 1 (proposed by pi_3)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 4: A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  trial 5: A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 6: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 7: A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 8: A=[0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 1]

**Rationale:** This design dissociates Probabilistic Cue Sampling (PCS) from Stochastic Take-The-Best (STTB) by exploiting their different responses to tied top-validity cues and multiple lower-validity cues. STTB searches sequentially in order of validity, terminating as soon as a cue discriminates. Thus, if the highest-validity cues tie, STTB simply moves to the next highest cue and bases its decision entirely on that single cue. In contrast, PCS samples a single cue proportionally to the softmax of validities. If the top cues tie, sampling them leads to guessing, allowing the accumulation of multiple lower-validity cues to dominate the overall choice probability. By presenting trials where the most valid discriminating cue favors option A, but a larger number of lower-validity cues favor option B, STTB will systematically choose A, whereas PCS will assign a higher aggregate probability to B.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
In all 8 trials of the design, the highest-validity discriminating cue favors option A, but a larger number of lower-validity cues favor option B. Stochastic Take-The-Best processes cues in validity order and will consistently choose A. Probabilistic Cue Sampling samples all cues proportionally to their validities, leading to a much higher rate of choosing B. The overall proportion of B choices (response == 1) will therefore be close to 0 for STTB (modulo errors) and significantly higher for PCS.

Source:
def metric(data: pd.DataFrame) -> float:
    # The experimental design is such that in EVERY trial, the first discriminating
    # cue (highest validity) favors option A, while the majority of lower-validity
    # cues favor option B.
    # STTB will systematically choose A (response = 0) because it terminates search
    # at the first discriminating cue.
    # PCS will sample lower-validity cues proportionally and therefore choose B (response = 1)
    # much more frequently.
    # Thus, the overall proportion of B choices directly discriminates the two theories.
    return float(data['response'].mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.5713 (var=0.0028)
- Predicted under pi_4 (simulated): 0.4154 (var=0.0108)
- Observed on real data: 0.5054 (var=0.0024)

## EXPERIMENT 2 (proposed by pi_4)

### DESIGN
**Validities (n_features=5):** [0.9, 0.85, 0.8, 0.75, 0.7]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  trial 2: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 4: A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  trial 6: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]

**Rationale:** This design dissociates Stochastic Take-The-Best (STTB) from Probabilistic Cue Sampling (PCS) by exploiting their divergent handling of tied cues and evidence accumulation. STTB evaluates cues strictly in descending order of validity; if the highest validity cue(s) tie, it skips them without accumulating evidence and bases its decision entirely on the first discriminating cue. In contrast, PCS samples cues based on a softmax distribution over validities. When top cues tie, sampling them leads to a 50/50 guess, effectively diluting the choice probability and allowing a larger number of lower-validity cues to dominate the aggregate decision. By presenting trials where the top cue ties and the next highest cue favors Option A, but all remaining lower-validity cues favor Option B, STTB will systematically choose A, whereas PCS will assign a higher overall probability to B.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of times the subject chooses Option A on a specific subset of trials (trials 1, 2, and 4). On these trials, the highest validity cues either tie or favor Option A, but a larger number of lower-validity cues favor Option B. According to the Stochastic Take-The-Best (STTB) theory, the subject will sequentially evaluate the cues and choose Option A based on the first discriminating high-validity cue, ignoring the sheer quantity of lower-validity cues supporting B. In contrast, the Probabilistic Cue Sampling (PCS) theory predicts that the subject samples cues probabilistically, and the combined weight of the numerous lower-validity cues favoring B will result in a higher probability of choosing Option B. Thus, the metric will be high (close to 1) for STTB and lower (below 0.5) for PCS.

Source:
def metric(data: pd.DataFrame) -> float:
    data['A_tuple'] = data['option_a_ratings'].apply(tuple)
    target_trials = [(1, 1, 0, 0, 0), (0, 1, 0, 0, 0), (1, 1, 1, 0, 0)]
    mask = data['A_tuple'].isin(target_trials)
    if mask.sum() == 0:
        return 0.5
    return float((data.loc[mask, 'response'] == 0).mean())

### RESULTS
- Predicted under pi_3 (simulated): 0.3842 (var=0.0043)
- Predicted under pi_4 (simulated): 0.5704 (var=0.0110)
- Observed on real data: 0.4892 (var=0.0034)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    tally_consistent = 0
    total_incongruent = 0
    
    for _, row in data.iterrows():
        a = list(row['option_a_ratings'])
        b = list(row['option_b_ratings'])
        resp = row['response']
        
        # Incongruent trial 1: Option A has fewer but higher-validity features
        if a == [1, 1, 0, 0, 0] and b == [0, 0, 1, 1, 1]:
            total_incongruent += 1
            if resp == 1:  # Tallying prefers B (3 features > 2 features)
                tally_consistent += 1
        
        # Incongruent trial 4: Option B has fewer but higher-validity features
        elif a == [0, 0, 1, 1, 1] and b == [1, 1, 0, 0, 0]:
            total_incongruent += 1
            if resp == 0:  # Tallying prefers A (3 features > 2 features)
                tally_consistent += 1
                
    if total_incongruent == 0:
        return 0.5
    return tally_consistent / total_incongruent
```

**Observed (real) value:** 0.5067 (var=0.0125)
**Predicted under pi_3:** 0.4892 (var=0.0113)
**Predicted under pi_4:** 0.3567 (var=0.0217)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Identify trials where one option has the two highest validity features [1, 1, 0, 0, 0]
    # and the other has the three lowest validity features [0, 0, 1, 1, 1].
    is_t1 = (data['option_a_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0))) & (data['option_b_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1)))
    is_t2 = (data['option_a_ratings'].apply(lambda x: tuple(x) == (0, 0, 1, 1, 1))) & (data['option_b_ratings'].apply(lambda x: tuple(x) == (1, 1, 0, 0, 0)))
    
    wadd_choices = 0
    total = 0
    
    if is_t1.any():
        wadd_choices += (data.loc[is_t1, 'response'] == 0).sum()
        total += is_t1.sum()
        
    if is_t2.any():
        wadd_choices += (data.loc[is_t2, 'response'] == 1).sum()
        total += is_t2.sum()
        
    return float(wadd_choices / total) if total > 0 else 0.5
```

**Observed (real) value:** 0.4800 (var=0.0099)
**Predicted under pi_3:** 0.4967 (var=0.0119)
**Predicted under pi_4:** 0.6583 (var=0.0169)

### Experiment 5
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Convert the option ratings lists into strings for safe hashing and comparison
    a_strs = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    b_strs = data['option_b_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    # Create an order-independent trial type identifier. 
    # Sorting ensures that A vs B and B vs A are mapped to the same trial type.
    trial_types = [a + '_' + b if a < b else b + '_' + a for a, b in zip(a_strs, b_strs)]
    df = data.assign(trial_type=trial_types)
    
    # Calculate the empirical choice proportion (p) for each subject and trial type.
    # Since variance p*(1-p) is symmetric, it doesn't matter which option's proportion we measure.
    p = df.groupby(['subject_id', 'trial_type'])['response'].mean()
    
    # Calculate the intra-subject variance of choices for each trial type
    var = p * (1.0 - p)
    
    # Return the mean intra-subject variance across all subjects and trial types
    return float(var.mean())
```

**Observed (real) value:** 0.2357 (var=0.0001)
**Predicted under pi_3:** 0.2280 (var=0.0001)
**Predicted under pi_4:** 0.2076 (var=0.0016)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    df = data.copy()
    # Create hashable trial identifiers safely using list comprehensions
    df['trial_id'] = df['option_a_ratings'].apply(lambda x: "".join([str(int(v)) for v in x])) + \
                     "_" + \
                     df['option_b_ratings'].apply(lambda x: "".join([str(int(v)) for v in x]))
    
    subj_vars = []
    for subj, subj_df in df.groupby('subject_id'):
        # Proportion of choosing A (response == 0) for each trial type
        p_A = subj_df.groupby('trial_id')['response'].apply(lambda x: np.mean(x == 0))
        # Variance of these proportions across the 12 trial types
        subj_vars.append(p_A.var(ddof=1))
        
    return float(np.mean(subj_vars))
```

**Observed (real) value:** 0.0341 (var=0.0001)
**Predicted under pi_3:** 0.0334 (var=0.0002)
**Predicted under pi_4:** 0.0484 (var=0.0009)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all experiments, Theory 1 (Probabilistic Cue Sampling) consistently outperforms Theory 2 (Stochastic Take-The-Best). In Experiments 3, 4, 5, and 6, Theory 1's predictions are remarkably close to the observed data, particularly capturing the near-chance (approx 0.5) behavior on incongruent trials and accurately matching the intra-subject variance. Theory 2 significantly deviates by predicting extreme choice proportions dictated by the single highest validity cue. However, in Experiments 1 and 2, observed choice proportions are also clustered tightly around 0.5, whereas Theory 1 predicts slight deviations (0.57 and 0.38) and Theory 2 predicts strong deviations. The observed data strongly suggests compensatory integration where conflicting sets of cues balance each other out, leading to indifference (0.5). Stochastic TTB fails fundamentally because it ignores lower-validity cues entirely. A fully compensatory model, such as a Weighted Additive (WADD) rule with a softmax decision function, might better capture the precise balancing of evidence that drives choice proportions so close to 0.5 on these carefully balanced trials.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Propose a 'Noisy Weighted Additive (WADD)' theory. Unlike Stochastic TTB (which is non-compensatory) and PCS (which samples a single cue per trial), the Noisy WADD theory posits that decision-makers compute a global utility for each option by summing the validities of all cues that favor it. They then translate the difference in these utilities into choice probabilities using a softmax function (potentially with a temperature parameter and a lapse rate). This compensatory mechanism allows multiple lower-validity cues to directly offset a single high-validity cue, naturally predicting the ~0.5 choice proportions observed in conflict trials across these experiments."
}
```

## Usage

```json
{
  "prompt_token_count": 6829,
  "candidates_token_count": 409,
  "total_token_count": 8265
}
```
