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
People make decisions by computing a weighted sum of the features for each option, where the weights correspond to a non-linear scaling of the subjective validities of the cues. This Weighted Additive (WADD) strategy allows for compensatory decision-making, where multiple weak cues can override a single strong cue, but the non-linear scaling (gamma parameter) flexibly tunes how strongly higher-validity cues dominate over weaker ones. A softmax choice rule on these weighted sums, along with a lapse rate, introduces response noise and accounts for the intermediate choice patterns observed in human data.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("WADD expects a (2, n_features) stimulus.")
        
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    gamma = float(parameters["gamma"])
    val = val ** gamma
    
    # Calculate weighted sum for each option
    score_a = np.sum(val * a)
    score_b = np.sum(val * b)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = len(p_core)
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))


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
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 2: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 5: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 6: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 7: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 8: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** This design aims to quantitatively dissociate the Weighted Additive (WADD) strategy from Tallying. Tallying ignores cue validities and simply counts the number of features favoring each option, predicting a perfect tie (50% choice) whenever the count of wins is equal, and predicting a strict preference whenever one option wins on more features. In contrast, WADD weights each feature by a non-linear scaling of its validity. By including trials where Tallying predicts a tie but WADD predicts a strong preference due to validity differences (e.g., A wins on 2 high-validity cues vs B wins on 2 low-validity cues), and trials where Tallying prefers one option but WADD prefers the other (e.g., A wins on 3 low-validity cues vs B wins on 1 or 2 high-validity cues), we can distinctly pull apart the validity-weighted compensatory mechanism of WADD from the unweighted counting mechanism of Tallying.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric isolates Trial 1, where the two options have exactly 2 positive features each. Tallying sees a perfect 2-vs-2 tie and predicts a 50% probability of choosing either option. However, Weighted Additive (WADD) strongly prefers the first option because its two positive features are the most valid ones (0.95 and 0.85), decisively outweighing the other option's features (0.75 and 0.65). Measuring the proportion of times subjects choose the high-validity option cleanly discriminates the guessing behavior of Tallying from the compensatory, validity-sensitive behavior of WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    opt1 = (1, 1, 0, 0, 0)
    opt2 = (0, 0, 1, 1, 0)
    
    chose_opt1 = []
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        if a == opt1 and b == opt2:
            chose_opt1.append(1 if row['response'] == 0 else 0)
        elif a == opt2 and b == opt1:
            chose_opt1.append(1 if row['response'] == 1 else 0)
            
    if not chose_opt1:
        return 0.5
    return sum(chose_opt1) / len(chose_opt1)

### RESULTS
- Predicted under pi_3 (simulated): 0.8183 (var=0.0255)
- Predicted under pi_2 (simulated): 0.5333 (var=0.0175)
- Observed on real data: 0.5100 (var=0.0385)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=6):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  trial 5: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 6: A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]

**Rationale:** This design strictly dissociates the unweighted feature-counting mechanism of Tallying from the validity-weighted compensatory mechanism of WADD. We include trials where Tallying predicts a perfect tie (because both options win on an equal number of features) but WADD predicts a strong preference due to differences in the validities of those features. We also include trials where Tallying favors an option that wins on a larger number of lower-validity cues, while WADD (depending on its gamma parameter) favors the option that wins on fewer but higher-validity cues. This creates a qualitative divergence in choice predictions, rather than just a difference in choice probabilities.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
This metric contrasts choice behavior on Trial 1 and Trial 4. In both trials, Tallying counts an equal number of winning features for Option A and Option B (2 wins each), predicting exactly a 50% chance of choosing A regardless of the beta parameter. Thus, for Tallying, the difference in the probability of choosing A between Trial 1 and Trial 4 is 0. In contrast, WADD weights features by their validities. In Trial 1, Option A wins on the two most valid features (0.95, 0.85), leading WADD to strongly prefer A. In Trial 4, Option A wins on the two least valid features (0.65, 0.55), leading WADD to strongly prefer B. Consequently, WADD predicts a large positive difference between the choice probabilities of A on Trial 1 vs Trial 4, cleanly discriminating the two theories.

Source:
def metric(data: pd.DataFrame) -> float:
    data = data.copy()
    data['A_str'] = data['option_a_ratings'].apply(lambda x: ''.join(map(str, x)))
    
    t1_mask = data['A_str'] == '11000'
    t4_mask = data['A_str'] == '00011'
    
    # response == 0 means subject chose A
    p_A_t1 = 1.0 - data.loc[t1_mask, 'response'].mean()
    p_A_t4 = 1.0 - data.loc[t4_mask, 'response'].mean()
    
    if pd.isna(p_A_t1): p_A_t1 = 0.5
    if pd.isna(p_A_t4): p_A_t4 = 0.5
    
    return float(p_A_t1 - p_A_t4)

### RESULTS
- Predicted under pi_3 (simulated): 0.6450 (var=0.0596)
- Predicted under pi_2 (simulated): 0.0050 (var=0.0284)
- Observed on real data: 0.0025 (var=0.0611)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]

**Metric**
```python
import pandas as pd
import numpy as np

def metric(data: pd.DataFrame) -> float:
    def ttb_choice(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for i in range(len(a)):
            if a[i] > b[i]:
                return 0
            elif b[i] > a[i]:
                return 1
        return 0.5
    
    ttb_preds = data.apply(ttb_choice, axis=1)
    return float(np.mean(data['response'] == ttb_preds))
```

**Observed (real) value:** 0.4425 (var=0.0035)
**Predicted under pi_3:** 0.5642 (var=0.0484)
**Predicted under pi_2:** 0.1537 (var=0.0079)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_aligned_choices = 0
    disagreement_trials = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        tally_a = np.sum(a > b)
        tally_b = np.sum(b > a)
        
        if tally_a > tally_b:
            tally_pred = 0
        elif tally_b > tally_a:
            tally_pred = 1
        else:
            tally_pred = None
            
        ttb_pred = None
        for i in range(len(a)):
            if a[i] > b[i]:
                ttb_pred = 0
                break
            elif b[i] > a[i]:
                ttb_pred = 1
                break
                
        if tally_pred is not None and ttb_pred is not None and tally_pred != ttb_pred:
            disagreement_trials += 1
            if row['response'] == ttb_pred:
                ttb_aligned_choices += 1
                
    if disagreement_trials == 0:
        return 0.5
        
    return float(ttb_aligned_choices / disagreement_trials)
```

**Observed (real) value:** 0.4578 (var=0.0041)
**Predicted under pi_3:** 0.4869 (var=0.0441)
**Predicted under pi_2:** 0.1403 (var=0.0096)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across Experiments 1 and 2, Tallying (THEORY 2) perfectly captures the observed data (predicting ~0.5), while WADD (THEORY 1) incorrectly predicts that subjects will strongly weight the high-validity cues. This shows that subjects are largely ignoring the cue validities and simply counting features. However, in Experiments 3 and 4, Tallying predicts a very strong preference (~85%) for the option with more features on trials where Tallying and Take-The-Best disagree, whereas humans show a much weaker preference (~55% for Tallying, 45% for TTB). Tallying's current parameterization is too deterministic. Since tied counts in Exps 1 and 2 will always yield 0.5 regardless of noise, adding more choice stochasticity (lower beta, higher epsilon) to Tallying will allow it to fit Exps 3 and 4 much better without harming its perfect predictions in Exps 1 and 2.",
  "verdict": "new_model",
  "target_theory_idx": 2,
  "recommendation": "Keep the Tallying mechanism but adjust the parameter ranges to generate much noisier predictions. Specifically, shift the range of the inverse temperature `beta` to lower values (closer to 0) and increase the range of the lapse rate `epsilon`. This will soften the predicted preference on unequal-count trials (bringing the Tallying predictions in Exps 3 and 4 up from ~0.15 to the observed ~0.45), while preserving the exact 0.5 predictions on tied-count trials in Exps 1 and 2."
}
```

## Usage

```json
{
  "prompt_token_count": 5312,
  "candidates_token_count": 367,
  "total_token_count": 7075
}
```
