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
Decision makers in multi-attribute choice tasks exhibit strategic heterogeneity. Rather than uniformly applying a single heuristic, the population consists of a mixture of strategies, predominantly Take The Best (TTB) and Tallying. On any given trial, a decision maker integrates the choice probabilities of these two heuristics according to their individual propensity (w_ttb). This mixture explains why aggregate choices in adversarial designs—where TTB and Tallying make opposing predictions—often hover around 50% alignment with either single heuristic.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"Expected a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    w_ttb = float(parameters["w_ttb"])
    
    # --- TTB Prediction ---
    val = np.asarray(parameters["validities"], dtype=float)
    cue_order = np.argsort(-val, kind="stable").tolist()
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        p_ttb = np.array([0.5, 0.5])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        z_ttb = beta * (scores_ttb - np.max(scores_ttb))
        e_ttb = np.exp(z_ttb)
        p_ttb = e_ttb / np.sum(e_ttb)
        
    # --- Tallying Prediction ---
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores_tal = np.array([a_wins, b_wins])
    z_tal = beta * (scores_tal - np.max(scores_tal))
    e_tal = np.exp(z_tal)
    p_tal = e_tal / np.sum(e_tal)
    
    # --- Mixture & Noise ---
    p_mix = w_ttb * p_ttb + (1.0 - w_ttb) * p_tal
    p_final = (1.0 - epsilon) * p_mix + epsilon * np.array([0.5, 0.5])
    
    return p_final

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
  trial 2: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  trial 4: A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  trial 5: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 6: A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  trial 7: A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  trial 8: A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]

**Rationale:** This design systematically varies the degree of conflict between Take The Best (TTB) and Tallying to dissociate a pure Tallying strategy from a mixture of TTB and Tallying. By including trials where TTB and Tallying strongly disagree (Tallying difference of 3), weakly disagree (Tallying difference of 1), agree, or where Tallying is tied but TTB is decisive, we can observe whether choices reflect a pure counting rule (which would track the tally difference monotonically and predict 50/50 on tally ties) or a mixture (which would show a persistent bias toward the TTB winner even when the tally strongly opposes it, and break tally ties decisively in the direction of TTB).

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric isolates trials where the Tallying heuristic is perfectly tied (trials 5 and 6). On these trials, a pure Tallying strategist has no basis for preference and must guess, resulting in a 50% match rate with the Take The Best (TTB) prediction. In contrast, the advocated mixture theory asserts that decision-makers integrate both heuristics; thus, when Tallying is indifferent, the TTB heuristic's preference breaks the tie, resulting in a significantly higher than 50% match rate with TTB.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        tally_a = np.sum(a > b)
        tally_b = np.sum(b > a)
        
        # Focus only on trials where Tallying predicts a tie
        if tally_a == tally_b:
            ttb_winner = None
            # Cue order matches index order since validities are strictly decreasing
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_winner = 0
                    break
                elif b[i] > a[i]:
                    ttb_winner = 1
                    break
            
            if ttb_winner is not None:
                matches.append(row['response'] == ttb_winner)
                
    if not matches:
        return 0.5
    return float(np.mean(matches))

### RESULTS
- Predicted under pi_3 (simulated): 0.6675 (var=0.0266)
- Predicted under pi_2 (simulated): 0.5067 (var=0.0049)
- Observed on real data: 0.5117 (var=0.0085)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.75, 0.65, 0.55]

**Trial pairs (n=8):**
  trial 1: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  trial 3: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 4: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 5: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 6: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 7: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  trial 8: A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]

**Rationale:** This design isolates the predictions of pure Tallying from a mixture of Tallying and Take The Best (TTB) by focusing on Tallying ties and strict Tallying margins. On trials where Tallying results in a tie (equal number of winning cues for A and B), the pure Tallying model predicts exactly 50/50 guessing regardless of the inverse temperature parameter. In contrast, the Mixture model predicts a systematic deviation from 50/50 in the direction of the highest-validity discriminating cue (TTB's choice). Furthermore, by including trials where Tallying favors one option by a narrow margin but TTB favors the other, we can cleanly separate the sensitivity to tally-differences from the persistent bias of the TTB component.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric calculates the proportion of choices that align with the Take The Best (TTB) heuristic specifically on trials where the Tallying heuristic results in a tie. Under the pure Tallying model, ties lead to exactly 50/50 guessing regardless of the beta parameter, so the expected value is 0.5. Under the Mixture model, the presence of TTB strategies will systematically bias choices towards the TTB prediction on these tie trials, resulting in a metric significantly greater than 0.5.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    ttb_aligned = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        
        if a_wins == b_wins:
            for i in range(len(a)):
                if a[i] > b[i]:
                    ttb_choice = 0
                    break
                elif b[i] > a[i]:
                    ttb_choice = 1
                    break
            else:
                continue
                
            ttb_aligned.append(int(row['response'] == ttb_choice))
            
    if len(ttb_aligned) == 0:
        return 0.5
    return float(np.mean(ttb_aligned))

### RESULTS
- Predicted under pi_3 (simulated): 0.6754 (var=0.0184)
- Predicted under pi_2 (simulated): 0.5271 (var=0.0046)
- Observed on real data: 0.4842 (var=0.0049)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    
    # Extract matrices of option features
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    # Calculate the difference
    diff = a_mat - b_mat
    
    # Using exponentially decreasing weights, the sign of the weighted sum
    # is completely determined by the first non-zero difference.
    # This exactly mimics the one-reason stopping rule of Take The Best.
    weights = np.array([10000, 1000, 100, 10, 1])
    weighted_diff = np.dot(diff, weights)
    
    # If weighted_diff > 0, A is favored by the first discriminating cue (TTB predicts 0).
    # If weighted_diff < 0, B is favored by the first discriminating cue (TTB predicts 1).
    ttb_pred = (weighted_diff < 0).astype(int)
    
    # Return the proportion of choices that align with the Take The Best prediction
    return float(np.mean(ttb_pred == data['response']))
```

**Observed (real) value:** 0.5025 (var=0.0034)
**Predicted under pi_3:** 0.5142 (var=0.0491)
**Predicted under pi_2:** 0.1288 (var=0.0054)

### Experiment 4
**Design**
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    matches = []
    for _, row in data.iterrows():
        a = np.array(row['option_a_ratings'])
        b = np.array(row['option_b_ratings'])
        a_wins = np.sum(a > b)
        b_wins = np.sum(b > a)
        tally_pred = 0 if a_wins > b_wins else 1
        matches.append(row['response'] == tally_pred)
    return float(np.mean(matches))
```

**Observed (real) value:** 0.5121 (var=0.0032)
**Predicted under pi_3:** 0.4844 (var=0.0419)
**Predicted under pi_2:** 0.8623 (var=0.0092)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across all four experiments, the observed metrics consistently hover around 0.5. In Experiments 1 and 2, when Tallying predicts a tie, subjects do not systematically break the tie using Take The Best (TTB), as pi_3 predicts (observed ~0.5, pi_3 ~0.67). In Experiments 3 and 4, where TTB and Tallying strongly conflict, subjects are again equally split (~0.5 alignment), contradicting pure Tallying (pi_2) which predicts strong alignment with the tally. The fact that choices remain near 50/50 regardless of whether the heuristics agree, conflict, or tie strongly suggests that subjects are largely guessing, likely due to task complexity, lack of feedback, or high response noise. Neither a pure heuristic nor a mixture of heuristics captures this pervasive indifference.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a 'High-Noise / Random Guessing' theory. The new theory should posit that due to the abstract nature of the task and lack of trial-by-trial feedback, subjects do not consistently apply structured multi-attribute heuristics. Instead, their choices are dominated by high response noise or a massive lapse rate, effectively resulting in random guessing on most trials. The model should predict uniform (0.5) probabilities across most, if not all, stimulus pairs, differentiating itself from both Tallying and TTB-Mixture models which predict decisive choices in at least some conditions."
}
```

## Usage

```json
{
  "prompt_token_count": 5504,
  "candidates_token_count": 333,
  "total_token_count": 8779
}
```
