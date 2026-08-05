# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_1" and "pi_2") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_1" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_2" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_1
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


## EXPERIMENT 1 (proposed by pi_1)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.65, 0.55, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 2: A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 3: A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 0]
  trial 4: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  trial 5: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  trial 6: A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  trial 7: A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  trial 8: A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]

**Rationale:** This design leverages the core difference between Tallying (which counts the number of features where an option is superior, ignoring validities) and WADD (which computes a validity-weighted sum). By using 5 features with a steep validity drop-off, we can construct trials where Option A wins on a larger number of low-validity features (favored by Tallying) while Option B wins on fewer but much higher-validity features (favored by WADD). We also include trials where Tallying predicts a perfect tie (equal number of winning features) but WADD strongly prefers one option, and baseline trials where both models agree.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric isolates trials where Tallying and WADD produce strongly divergent predictions. In trials 1 and 2, Tallying counts more winning features for the option with lower validities, whereas WADD's weighted sum favors the option with fewer but highly valid features. In trials 3 and 4, Tallying predicts a perfect tie (random guessing), while WADD still maintains a systematic preference due to validity weighting. By computing the proportion of choices that align with the Tallying-favored (or Tallying-neutral) direction, we obtain a metric that should be around 0.75 for Tallying and significantly lower for WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    score = 0.0
    count = 0
    for _, row in data.iterrows():
        a = tuple(row['option_a_ratings'])
        b = tuple(row['option_b_ratings'])
        resp = row['response']
        
        # Trial 1: Tallying strongly prefers A, WADD generally prefers B
        if a == (0, 0, 1, 1, 1) and b == (1, 1, 0, 0, 0):
            score += (1 - resp)
            count += 1
        # Trial 2: Tallying strongly prefers B, WADD generally prefers A
        elif a == (1, 1, 0, 0, 0) and b == (0, 0, 1, 1, 1):
            score += resp
            count += 1
        # Trial 3: Tallying is indifferent (50/50), WADD generally prefers B
        elif a == (0, 1, 0, 0, 1) and b == (1, 0, 1, 0, 0):
            score += (1 - resp)
            count += 1
        # Trial 4: Tallying is indifferent (50/50), WADD generally prefers A
        elif a == (1, 0, 1, 0, 0) and b == (0, 1, 0, 0, 1):
            score += resp
            count += 1
            
    return float(score / count) if count > 0 else 0.5

### RESULTS
- Predicted under pi_1 (simulated): 0.6808 (var=0.0049)
- Predicted under pi_2 (simulated): 0.5171 (var=0.0377)
- Observed on real data: 0.1575 (var=0.0090)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=5):** [0.95, 0.85, 0.6, 0.55, 0.5]

**Trial pairs (n=6):**
  trial 1: A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  trial 2: A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  trial 3: A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  trial 4: A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  trial 5: A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  trial 6: A=[0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0]

**Rationale:** To strongly dissociate WADD from Tallying, this design uses 5 features with a steep drop-off in validities. We construct trials where one option wins on a larger number of low-validity features (favored by Tallying) while the other option wins on fewer but higher-validity features (favored by WADD). We also include tie-breaking trials where both options win on an equal number of features (Tallying predicts guessing) but WADD strongly prefers the option with the higher-validity features. Finally, baseline trials where both models agree are included to ensure general task engagement.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
On Trial 1, Option A has more positive features (3 vs 2), meaning Tallying will strongly prefer Option A. However, Option B's positive features are the two most valid ones (validities 0.95 and 0.85) while Option A's are the three least valid ones. Weighted Additive (WADD) will therefore generally assign a higher score to Option B and prefer it. By calculating the proportion of Option A choices on this specific trial, we obtain a metric that should be significantly higher for Tallying than for WADD.

Source:
def metric(data: pd.DataFrame) -> float:
    # Convert option A ratings to a string for easy matching
    a_str = data['option_a_ratings'].apply(lambda x: ''.join([str(int(v)) for v in x]))
    
    # Identify Trial 1: A = [0, 0, 1, 1, 1], B = [1, 1, 0, 0, 0]
    t1_mask = a_str == '00111'
    
    if t1_mask.sum() == 0:
        return 0.5
        
    # Return the proportion of times the subject chose Option A (response == 0)
    return float((data.loc[t1_mask, 'response'] == 0).mean())

### RESULTS
- Predicted under pi_1 (simulated): 0.8550 (var=0.0190)
- Predicted under pi_2 (simulated): 0.5000 (var=0.0906)
- Observed on real data: 0.1400 (var=0.0213)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
(no other experiments)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "The observed data heavily contradicts THEORY 1 (Tallying). In both experiments, Tallying predicts that subjects will choose the option with more positive features (Option A), leading to predicted metrics of ~0.68 and ~0.85. However, the observed metrics are ~0.15 and ~0.14, indicating a strong preference for Option B. Option B consistently possesses fewer positive features, but those features have the highest validities. While THEORY 2 (WADD) conceptually accounts for validity weighting, its current model implementation averages out to ~0.5 due to unconstrained parameter sampling of subjective validities. The strong, near-deterministic preference for the option winning on the highest-validity cue suggests subjects are heavily relying on the most valid features, likely in a non-compensatory manner.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace Tallying with the 'Take The Best' (TTB) heuristic. TTB posits a non-compensatory, lexicographic decision process: subjects search through cues in descending order of validity (which corresponds to the left-to-right index order of the feature arrays). The first cue that discriminates between the two options strictly determines the choice, completely ignoring all remaining lower-validity cues. If no cues discriminate, the subject guesses. This theory will naturally capture the strong observed preference for options that win on the most valid feature, directly correcting Tallying's backwards predictions."
}
```

## Usage

```json
{
  "prompt_token_count": 4337,
  "candidates_token_count": 328,
  "total_token_count": 6614
}
```
