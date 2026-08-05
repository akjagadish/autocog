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
Decision makers evaluate options by computing a weighted sum of their feature values, where the weights correspond to a non-linear scaling of the subjective or instructed validities of the cues. This non-linear Weighted Additive (WADD) strategy includes an exponent parameter (gamma) on the validities, allowing the decision process to smoothly interpolate between equal weighting (Tallying, gamma=0), proportional weighting (standard WADD, gamma=1), and lexicographic one-reason decision making (Take The Best, gamma > 1). The option with the higher total weighted score is favored, with response noise modeled via a softmax function over the scores and an independent lapse rate. To capture the fact that human behavior can sometimes be entirely random, the lapse rate and inverse temperature parameters are allowed to span their full theoretical ranges (up to pure guessing).

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    # Stimulus is the pair of option feature vectors for the current trial:
    # array-like of shape (2, n_features), row 0 = option A, row 1 = option B.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    # Validities are used as weights for the additive sum.
    val = np.asarray(parameters["validities"], dtype=float)
    if val.shape[0] != stim.shape[1]:
        raise ValueError("Length of validities must match n_features.")
        
    # Apply non-linear scaling to validities
    gamma = float(parameters["gamma"])
    val = val ** gamma
    
    a, b = stim[0], stim[1]
    
    # Compute the weighted sum (WADD score) for each option.
    score_a = np.dot(a, val)
    score_b = np.dot(b, val)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    # Softmax with max-subtraction for numerical stability.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities = probabilities / probabilities.sum()
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
**Validities (n_features=5):** [0.95, 0.8, 0.75, 0.6, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 2: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 3: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 5: A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  trial 6: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 7: A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]

**Rationale:** To quantitatively dissociate Non-linear WADD from Tallying, we must decouple the sheer count of winning features from the cumulative validity of those features. Tallying strictly predicts choices based on the number of feature-wise wins, collapsing to random guessing (50/50) whenever the number of winning features is equal. In contrast, Non-linear WADD integrates the validities of the winning features, scaled by a non-linear parameter (gamma). This design includes trials where Tallying predicts a tie but WADD predicts a strong preference based on validity (e.g., winning on 2 high-validity vs 2 low-validity features). It also includes trials where Tallying favors one option (more wins) but WADD favors the other (fewer wins, but on features with much higher validities), allowing us to estimate the gamma parameter and show that subjects are sensitive to validity magnitudes rather than just counts.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric isolates trials where the Tallying heuristic predicts a strict tie (both options win on an equal number of features). Under Tallying, subjects must guess on these trials, resulting in a choice proportion of 0.5. However, under the Non-linear WADD theory, subjects integrate the validities of the features. Because the first feature has the highest validity (0.95), WADD strongly predicts that subjects will choose the option that wins on this feature, breaking the tallying tie. The metric calculates the proportion of tie trials where the choice aligns with the most valid feature, expecting ~0.5 for Tallying and >0.5 for WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    consistent_choices = 0
    total_ties = 0
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        # Identify trials where Tallying predicts a tie
        if a_wins == b_wins:
            # Determine which option wins on the highest validity feature (index 0)
            if a[0] > b[0]:
                wadd_prediction = 0
            elif b[0] > a[0]:
                wadd_prediction = 1
            else:
                continue
                
            if row['response'] == wadd_prediction:
                consistent_choices += 1
            total_ties += 1
            
    if total_ties == 0:
        return 0.5
        
    return float(consistent_choices) / total_ties


### RESULTS
- Predicted under pi_3 (simulated): 0.6129 (var=0.0216)
- Predicted under pi_2 (simulated): 0.4988 (var=0.0046)
- Observed on real data: 0.5208 (var=0.0104)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=10):**
  trial 1: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 2: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 3: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 4: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 6: A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  trial 7: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  trial 9: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 10: A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 1]

**Rationale:** This design strictly dissociates Tallying from Non-linear WADD by systematically varying the count of winning features independently of their validities. Tallying relies solely on the number of strict feature-wise wins, predicting a uniform 50/50 guess whenever the number of wins is tied, and a robust preference whenever one option has more wins, completely ignoring validity magnitudes. WADD, by contrast, weights wins by their validities (scaled by gamma). The trial set includes 'Tallying Ties' where options win on an equal number of features but differ in validity (WADD strongly prefers the high-validity option), and 'Reversal' trials where one option wins on more features (favored by Tallying) but the other wins on fewer, higher-validity features (favored by WADD).

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
This metric isolates trials where Tallying sees a perfect tie (equal number of strict feature wins for both options) but WADD has a strict preference due to the different validities of the winning features. On these trials, Tallying predicts that the subject will guess uniformly at random (50%), regardless of the inverse temperature parameter. WADD, however, predicts a systematic preference for the option with the higher validity-weighted sum. The metric calculates the proportion of choices that align with WADD's preference on these specific trials. Tallying will yield a value clustered tightly around 0.5, whereas WADD will yield a value significantly greater than 0.5.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    val = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    wadd_pref_chosen = []
    
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        # Focus on Tallying-tie trials
        if a_wins == b_wins:
            score_a = np.dot(a, val)
            score_b = np.dot(b, val)
            
            # Where WADD has a strict preference
            if abs(score_a - score_b) > 1e-5:
                wadd_pref = 0 if score_a > score_b else 1
                if row['response'] == wadd_pref:
                    wadd_pref_chosen.append(1)
                else:
                    wadd_pref_chosen.append(0)
                    
    if len(wadd_pref_chosen) == 0:
        return 0.5
        
    return float(np.mean(wadd_pref_chosen))

### RESULTS
- Predicted under pi_3 (simulated): 0.6694 (var=0.0140)
- Predicted under pi_2 (simulated): 0.4994 (var=0.0064)
- Observed on real data: 0.5167 (var=0.0067)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    def get_ttb_winner(a, b):
        for i in range(len(a)):
            if a[i] > b[i]: return 0
            if b[i] > a[i]: return 1
        return -1
    
    agreements = []
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        resp = row['response']
        w = get_ttb_winner(a, b)
        if w != -1:
            agreements.append(1.0 if resp == w else 0.0)
            
    if not agreements:
        return 0.5
    return float(np.mean(agreements))
```

**Observed (real) value:** 0.4983 (var=0.0017)
**Predicted under pi_3:** 0.5056 (var=0.0054)
**Predicted under pi_2:** 0.3210 (var=0.0037)

### Experiment 4
**Design**
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    match_count = 0
    valid_trials = 0
    
    for _, row in data.iterrows():
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        
        a_wins = sum(1 for x, y in zip(a, b) if x > y)
        b_wins = sum(1 for x, y in zip(a, b) if y > x)
        
        if a_wins > b_wins:
            tally_choice = 0
        elif b_wins > a_wins:
            tally_choice = 1
        else:
            continue
            
        if row['response'] == tally_choice:
            match_count += 1
        valid_trials += 1
        
    if valid_trials == 0:
        return 0.5
    return match_count / valid_trials
```

**Observed (real) value:** 0.4921 (var=0.0015)
**Predicted under pi_3:** 0.5984 (var=0.0137)
**Predicted under pi_2:** 0.8444 (var=0.0068)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the four experiments, the observed behavior consistently hovers around 0.50 for the chosen metrics. In Experiments 1 and 2, Tallying (Theory 2) accurately predicts ~0.50 because the metrics isolate Tallying ties, whereas WADD (Theory 1) predicts a preference based on validity (0.61 and 0.67). However, in Experiments 3 and 4, Tallying completely fails to capture the data. In Experiment 4, the metric measures agreement with Tallying on non-tied trials; Tallying naturally predicts a high agreement (0.84), but the observed data is 0.49. This indicates that subjects are decidedly NOT using Tallying when it makes a clear prediction. Neither theory perfectly captures the ~0.50 observation across all splits, but WADD's predictions are generally less extreme than Tallying's failures. Tallying is fundamentally degenerate here because it strongly predicts effects in Exp 3 and 4 that simply do not exist in the human data.",
  "verdict": "new_theory",
  "target_theory_idx": 2,
  "recommendation": "Replace the Tallying theory with a 'Take-The-Best' (TTB) or Lexicographic theory. TTB postulates that decision makers search through cues in order of validity and stop at the first cue that discriminates between the options, completely ignoring all remaining cues. This contrasts with both Tallying (which counts all cues equally) and WADD (which integrates all cues). TTB might better explain the ~0.50 agreement in Experiment 4 if TTB's predictions are systematically orthogonal to Tallying's predictions on those trials. Include parameters for search errors or lapse rates to accommodate the high degree of noise in the observed data."
}
```

## Usage

```json
{
  "prompt_token_count": 5605,
  "candidates_token_count": 399,
  "total_token_count": 7816
}
```
