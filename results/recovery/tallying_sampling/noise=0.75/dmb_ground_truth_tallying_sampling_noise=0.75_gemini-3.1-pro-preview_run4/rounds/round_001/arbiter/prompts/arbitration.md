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
Strategy Mixture Model: Decision-making in multi-attribute choice is heterogeneous. Individuals (or single decisions) rely on a probabilistic mixture of non-compensatory heuristics (like Take The Best) and compensatory integration (like Weighted Additive). Because TTB and WADD produce scores on fundamentally different scales, their choice determinism is parameterized independently. This allows the mixture to flexibly capture the intermediate match rates observed in empirical data without being constrained by an artificial coupling of noise levels across strategies.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np
    
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError("Stimulus must be shape (2, n_features).")
        
    val = np.asarray(parameters["validities"], dtype=float)
    
    # --- Take The Best (TTB) --- 
    cue_order = np.argsort(-val, kind="stable").tolist()
    a, b = stim[0], stim[1]
    winner_ttb = None
    for j in cue_order:
        if a[j] > b[j]:
            winner_ttb = 0
            break
        if b[j] > a[j]:
            winner_ttb = 1
            break
            
    if winner_ttb is None:
        scores_ttb = np.array([0.0, 0.0])
    else:
        scores_ttb = np.array([1.0, 0.0]) if winner_ttb == 0 else np.array([0.0, 1.0])
        
    # --- Weighted Additive (WADD) ---
    scores_wadd = stim @ val
    
    beta_ttb = float(parameters["beta_ttb"])
    beta_wadd = float(parameters["beta_wadd"])
    
    # Softmax for TTB
    z_ttb = beta_ttb * (scores_ttb - scores_ttb.max())
    e_ttb = np.exp(z_ttb)
    p_ttb = e_ttb / e_ttb.sum()
    
    # Softmax for WADD
    z_wadd = beta_wadd * (scores_wadd - scores_wadd.max())
    e_wadd = np.exp(z_wadd)
    p_wadd = e_wadd / e_wadd.sum()
    
    # --- Mixture ---
    w_ttb = float(parameters["w_ttb"])
    p_mix = w_ttb * p_ttb + (1.0 - w_ttb) * p_wadd
    
    # --- Lapse ---
    epsilon = float(parameters["epsilon"])
    n_opts = p_mix.shape[0]
    return (1.0 - epsilon) * p_mix + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))


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

**Trial pairs (n=12):**
  trial 1: A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  trial 2: A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  trial 4: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 5: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 6: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 7: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  trial 8: A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  trial 9: A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  trial 10: A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  trial 11: A=[0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1]
  trial 12: A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0]

**Rationale:** To quantitatively dissociate the Strategy Mixture Model from a pure Weighted Additive (WADD) model, we exploit the fact that a pure WADD model predicts choice probabilities that are strictly a monotonic function of the difference in weighted sums (a single sigmoid curve). The Strategy Mixture Model, however, predicts that choices are a mixture of WADD and Take The Best (TTB). Therefore, if we plot the probability of choosing Option A against the WADD difference (WADD_A - WADD_B), the Mixture Model predicts that the points will split into distinct curves depending on which option TTB favors. We construct pairs that systematically vary the WADD difference while orthogonally manipulating the TTB prediction (e.g., pairs where WADD strongly favors B but TTB favors A, and vice versa). A pure WADD model cannot account for vertical shifts in choice probability at the same WADD difference caused by the non-compensatory TTB component.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
The Strategy Mixture Model posits that subjects probabilistically mix the Take The Best (TTB) heuristic and the Weighted Additive (WADD) strategy. Under pure WADD, when the weighted sum strongly favors one option, the subject will choose that option (subject to random noise). Under the Strategy Mixture Model, however, if TTB favors the opposite option, there will be a substantial rate of choosing the TTB-favored option (driven by the w_ttb mixture component). By isolating 'conflict trials' where TTB and WADD disagree, we can compute the proportion of times the subject chooses the TTB-favored option. A pure WADD model predicts this proportion will be very low (close to the lapse rate), whereas the Mixture Model predicts a significantly higher proportion.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    val = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    a_mat = np.stack(data['option_a_ratings'].values)
    b_mat = np.stack(data['option_b_ratings'].values)
    
    diff = a_mat - b_mat
    abs_diff = np.abs(diff)
    
    # TTB winner: first cue where options differ
    first_diff_idx = np.argmax(abs_diff, axis=1)
    ttb_winner = np.where(diff[np.arange(len(diff)), first_diff_idx] > 0, 0, 1)
    
    # WADD winner
    wadd_a = a_mat @ val
    wadd_b = b_mat @ val
    
    wadd_winner = np.where(wadd_a > wadd_b, 0, 1)
    valid = (wadd_a != wadd_b) & (np.max(abs_diff, axis=1) > 0)
    
    conflict = valid & (ttb_winner != wadd_winner)
    
    if not np.any(conflict):
        return 0.5
        
    responses = data['response'].values
    ttb_chosen = (responses[conflict] == ttb_winner[conflict]).sum()
    
    return float(ttb_chosen / np.sum(conflict))

### RESULTS
- Predicted under pi_3 (simulated): 0.4631 (var=0.0390)
- Predicted under pi_2 (simulated): 0.2669 (var=0.0255)
- Observed on real data: 0.4044 (var=0.0030)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.9, 0.8, 0.7, 0.6, 0.5]

**Trial pairs (n=10):**
  trial 1: A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 1]
  trial 2: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  trial 3: A=[1, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  trial 4: A=[0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 5: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 6: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  trial 7: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  trial 8: A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  trial 9: A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  trial 10: A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]

**Rationale:** By fixing validities such that multiple pairs produce an exact tie in the objective Weighted Additive (WADD) score, we can sharply dissociate the Advocated WADD model (which features free weighting parameters per cue) from the Strategy Mixture Model (which restricts its WADD component to use exact objective validities). For these objective-WADD-tied pairs, the Strategy Mixture Model is strictly forced to predict a preference aligned with the Take The Best (TTB) heuristic, because the WADD component provides no directional preference. In contrast, the Advocated WADD model can accommodate choices that go against TTB on these 'tied' trials by allowing subjective weights to deviate from objective validities. We include a spectrum of objective WADD ties, small differences, and opposing TTB predictions to fully expose this parameterization difference.

**Computed schedule:** 10 unique pairs × 9 reps = 90 trials per subject.



### METRIC
Rationale:
By isolating trials where the objective WADD scores are exactly equal, we can sharply discriminate the two theories. The Strategy Mixture Model relies on exact objective validities for its WADD component; thus, on tied trials, its WADD component provides no directional preference (predicting 50/50), allowing the TTB component to dominate and drive choices toward the TTB prediction. In contrast, the Advocated WADD model uses free, subjective weights. Because subjective weights fluctuate randomly around the objective validities, the subjective WADD scores will rarely tie, and the model will predict choices that distribute roughly symmetrically around 50% for these trials, yielding a significantly lower TTB match rate than the Strategy Mixture Model.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    val = np.array([0.9, 0.8, 0.7, 0.6, 0.5])
    
    a_ratings = np.stack(data['option_a_ratings'].values)
    b_ratings = np.stack(data['option_b_ratings'].values)
    
    wadd_a = a_ratings @ val
    wadd_b = b_ratings @ val
    
    # Identify trials where the objective WADD model predicts a tie
    tied_trials = np.abs(wadd_a - wadd_b) < 1e-5
    if not np.any(tied_trials):
        return 0.5
    
    a_tied = a_ratings[tied_trials]
    b_tied = b_ratings[tied_trials]
    responses = data['response'].values[tied_trials]
    
    # In all tied trials, cue 1 (the highest validity cue) discriminates the options.
    # TTB predicts A (0) if A has cue 1, else B (1).
    ttb_preds = (b_tied[:, 0] > a_tied[:, 0]).astype(int)
    
    return float(np.mean(responses == ttb_preds))

### RESULTS
- Predicted under pi_3 (simulated): 0.6789 (var=0.0228)
- Predicted under pi_2 (simulated): 0.5050 (var=0.0527)
- Observed on real data: 0.4867 (var=0.0072)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    def get_ttb_response(row):
        a = row['option_a_ratings']
        b = row['option_b_ratings']
        for j in range(len(a)):
            if a[j] > b[j]:
                return 0
            elif b[j] > a[j]:
                return 1
        return 0.5
    
    ttb_preds = data.apply(get_ttb_response, axis=1)
    return float(np.mean(data['response'] == ttb_preds))
```

**Observed (real) value:** 0.4392 (var=0.0021)
**Predicted under pi_3:** 0.5523 (var=0.0387)
**Predicted under pi_2:** 0.3152 (var=0.0188)

### Experiment 4
**Design**
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.55])
    
    a_ratings = np.array(data['option_a_ratings'].tolist())
    b_ratings = np.array(data['option_b_ratings'].tolist())
    
    wadd_a = a_ratings @ validities
    wadd_b = b_ratings @ validities
    wadd_prefers_a = wadd_a > wadd_b
    wadd_prefers_b = wadd_b > wadd_a
    
    diff = a_ratings - b_ratings
    ttb_prefers_a = np.zeros(len(data), dtype=bool)
    ttb_prefers_b = np.zeros(len(data), dtype=bool)
    
    for i in range(len(data)):
        for j in range(5):
            if diff[i, j] > 0:
                ttb_prefers_a[i] = True
                break
            elif diff[i, j] < 0:
                ttb_prefers_b[i] = True
                break
                
    conflict = (ttb_prefers_a & wadd_prefers_b) | (ttb_prefers_b & wadd_prefers_a)
    
    if not np.any(conflict):
        return 0.5
        
    response = data['response'].values
    ttb_match = (ttb_prefers_a & (response == 0)) | (ttb_prefers_b & (response == 1))
    
    return float(np.mean(ttb_match[conflict]))
```

**Observed (real) value:** 0.4100 (var=0.0050)
**Predicted under pi_3:** 0.4878 (var=0.0578)
**Predicted under pi_2:** 0.2984 (var=0.0285)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the experiments, observed TTB match rates on conflict trials hover around 0.40 to 0.44, indicating a slight preference for the compensatory (WADD) option over the non-compensatory (TTB) option. In Experiment 2, where objective WADD scores are tied, the observed TTB match rate is ~0.48 (essentially guessing). Theory 1 (pi_3, Strategy Mixture) consistently overestimates TTB reliance, predicting match rates between 0.46 and 0.67, struggling especially on the tied trials because its objective WADD component provides no signal, leaving TTB to dominate. Theory 2 (pi_2, Subjective WADD) captures the tied trials well (predicting ~0.50) but underestimates the TTB match rate on conflict trials (predicting ~0.26-0.31), meaning it is too strongly compensatory. Neither theory captures the data perfectly, but the rigid mixture of pure TTB and objective WADD in Theory 1 is structurally limiting.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose a brand-new theory to replace the Strategy Mixture Model. A promising direction is a 'Non-linear Weighting' or 'Lexicographic Semi-Order' model. Instead of probabilistically mixing two separate strategies, subjects might use a single integration process where cue validities are transformed non-linearly (e.g., via a rank-dependent or exponential decay function). This would naturally produce behavior that looks partially like TTB (due to steep drops in subjective weight for lower-ranked cues) but remains fundamentally compensatory, allowing it to better match the ~0.40-0.45 TTB selection rate on conflict trials while naturally predicting guessing on effectively tied trials."
}
```

## Usage

```json
{
  "prompt_token_count": 6278,
  "candidates_token_count": 399,
  "total_token_count": 8074
}
```
