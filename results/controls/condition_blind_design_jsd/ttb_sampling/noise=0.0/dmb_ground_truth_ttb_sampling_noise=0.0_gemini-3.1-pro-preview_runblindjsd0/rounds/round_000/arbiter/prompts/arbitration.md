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
**Validities (n_features=4):** [0.95, 0.76, 0.92, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[1, 1, 0, 0]  B=[1, 1, 1, 0]
  trial 2: A=[1, 1, 1, 0]  B=[0, 1, 0, 0]
  trial 3: A=[1, 0, 0, 1]  B=[0, 1, 1, 1]
  trial 4: A=[0, 1, 1, 1]  B=[0, 0, 0, 0]
  trial 5: A=[1, 1, 1, 0]  B=[1, 0, 1, 0]
  trial 6: A=[0, 0, 1, 0]  B=[1, 0, 0, 0]
  trial 7: A=[1, 0, 1, 1]  B=[0, 0, 1, 1]
  trial 8: A=[1, 0, 0, 1]  B=[1, 1, 1, 0]
  trial 9: A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  trial 10: A=[0, 1, 0, 0]  B=[1, 1, 0, 1]
  trial 11: A=[1, 0, 1, 0]  B=[0, 0, 0, 1]
  trial 12: A=[0, 1, 0, 0]  B=[1, 0, 0, 1]
  trial 13: A=[1, 0, 0, 0]  B=[1, 1, 0, 0]
  trial 14: A=[1, 1, 0, 1]  B=[0, 0, 1, 1]
  trial 15: A=[0, 0, 1, 1]  B=[0, 1, 1, 1]
  trial 16: A=[0, 0, 0, 1]  B=[1, 0, 1, 1]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((1, 1, 1, 0), (0, 1, 0, 0))|0': 0.13670886075949368, '((1, 1, 1, 0), (0, 1, 0, 0))|1': 0.11287128712871287, '((0, 1, 1, 1), (0, 0, 0, 0))|0': 0.12745098039215685, '((0, 1, 1, 1), (0, 0, 0, 0))|1': 0.11979166666666667, '((1, 0, 0, 1), (0, 1, 1, 1))|0': 0.8440779610194903, '((1, 0, 0, 1), (0, 1, 1, 1))|1': 0.8649602824360106, '((1, 0, 0, 1), (1, 1, 1, 0))|0': 0.8597081930415263, '((1, 0, 0, 1), (1, 1, 1, 0))|1': 0.8404840484048405, '((1, 1, 1, 0), (1, 0, 1, 0))|0': 0.18133333333333335, '((1, 1, 1, 0), (1, 0, 1, 0))|1': 0.13894736842105262, '((0, 1, 0, 0), (1, 1, 0, 1))|0': 0.856301531213192, '((0, 1, 0, 0), (1, 1, 0, 1))|1': 0.8494623655913979, '((0, 1, 0, 0), (1, 0, 0, 1))|0': 0.8326180257510729, '((0, 1, 0, 0), (1, 0, 0, 1))|1': 0.8746594005449592, '((1, 0, 1, 0), (0, 0, 0, 1))|0': 0.1670235546038544, '((1, 0, 1, 0), (0, 0, 0, 1))|1': 0.14103525881470366, '((1, 0, 1, 1), (0, 0, 1, 1))|0': 0.19970845481049562, '((1, 0, 1, 1), (0, 0, 1, 1))|1': 0.1490125673249551, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8724727838258165, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8755401901469317, '((1, 1, 0, 1), (0, 0, 1, 1))|0': 0.14446952595936793, '((1, 1, 0, 1), (0, 0, 1, 1))|1': 0.14660831509846828, '((0, 0, 1, 1), (0, 1, 1, 1))|0': 0.8440233236151603, '((0, 0, 1, 1), (0, 1, 1, 1))|1': 0.86983842010772, '((1, 1, 0, 0), (1, 1, 1, 0))|0': 0.752851711026616, '((1, 1, 0, 0), (1, 1, 1, 0))|1': 0.8666232921275211, '((1, 0, 0, 0), (1, 1, 0, 0))|0': 0.8525730180806675, '((1, 0, 0, 0), (1, 1, 0, 0))|1': 0.8287292817679558, '((0, 0, 0, 1), (1, 0, 1, 1))|0': 0.8569463548830811, '((0, 0, 0, 1), (1, 0, 1, 1))|1': 0.8825722273998136, '((0, 0, 1, 0), (1, 0, 0, 0))|0': 0.5039370078740157, '((0, 0, 1, 0), (1, 0, 0, 0))|1': 0.5093304061470911}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0


### RESULTS
- Predicted under pi_1 (simulated): 0.0010 (var=0.0001)
- Predicted under pi_2 (simulated): 0.0045 (var=0.0004)
- Observed on real data: 0.0251 (var=0.0002)

## EXPERIMENT 2 (proposed by pi_2)

### DESIGN
**Validities (n_features=4):** [0.95, 0.89, 0.88, 0.55]

**Trial pairs (n=16):**
  trial 1: A=[0, 0, 1, 1]  B=[1, 1, 1, 1]
  trial 2: A=[0, 0, 0, 0]  B=[1, 0, 0, 0]
  trial 3: A=[0, 1, 0, 1]  B=[1, 0, 1, 1]
  trial 4: A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  trial 5: A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  trial 6: A=[0, 1, 1, 0]  B=[1, 1, 0, 1]
  trial 7: A=[0, 0, 0, 0]  B=[0, 0, 0, 1]
  trial 8: A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  trial 9: A=[0, 0, 0, 1]  B=[1, 1, 1, 0]
  trial 10: A=[0, 0, 1, 1]  B=[1, 1, 1, 0]
  trial 11: A=[1, 1, 0, 1]  B=[1, 0, 1, 1]
  trial 12: A=[0, 0, 1, 0]  B=[1, 0, 1, 0]
  trial 13: A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  trial 14: A=[1, 0, 0, 0]  B=[1, 1, 0, 1]
  trial 15: A=[1, 1, 1, 1]  B=[1, 1, 0, 0]
  trial 16: A=[0, 1, 1, 0]  B=[0, 0, 0, 1]

**Rationale:** (no rationale)

**Computed schedule:** 16 unique pairs × 6 reps = 96 trials per subject.



### METRIC
Rationale:
Auto-generated JSD-to-self metric (jsd_metric control): sequence-aware Jensen-Shannon divergence (nats, 0 to ln 2) between the dataset's conditional choice profile and the proposing theory's, over (trial content, previous response) states. 0 means the data behaves exactly like the proposing theory; ln 2 means maximally different.

Source:
P_REF = {'((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8286189683860233, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8557130942452044, '((0, 0, 0, 1), (1, 1, 1, 0))|0': 0.8488210818307905, '((0, 0, 0, 1), (1, 1, 1, 0))|1': 0.8591288229842446, '((0, 1, 0, 1), (1, 0, 1, 1))|0': 0.6946564885496184, '((0, 1, 0, 1), (1, 0, 1, 1))|1': 0.7695924764890282, '((0, 1, 0, 1), (1, 1, 0, 0))|0': 0.6170886075949367, '((0, 1, 0, 1), (1, 1, 0, 0))|1': 0.6438356164383562, '((0, 0, 1, 1), (1, 1, 1, 0))|0': 0.7890625, '((0, 0, 1, 1), (1, 1, 1, 0))|1': 0.8189655172413793, '((1, 1, 1, 1), (1, 1, 0, 0))|0': 0.18725099601593626, '((1, 1, 1, 1), (1, 1, 0, 0))|1': 0.16024653312788906, '((1, 0, 0, 0), (1, 1, 0, 1))|0': 0.8076923076923077, '((1, 0, 0, 0), (1, 1, 0, 1))|1': 0.842156862745098, '((0, 0, 1, 1), (1, 1, 1, 1))|0': 0.8343465045592705, '((0, 0, 1, 1), (1, 1, 1, 1))|1': 0.8537653239929948, '((0, 1, 0, 1), (0, 0, 0, 1))|0': 0.23655913978494625, '((0, 1, 0, 1), (0, 0, 0, 1))|1': 0.20869565217391303, '((0, 0, 1, 0), (1, 0, 1, 0))|0': 0.758364312267658, '((0, 0, 1, 0), (1, 0, 1, 0))|1': 0.8026183282980867, '((0, 1, 1, 0), (1, 1, 0, 1))|0': 0.6039119804400978, '((0, 1, 1, 0), (1, 1, 0, 1))|1': 0.7167505391804457, '((0, 0, 0, 0), (1, 0, 0, 0))|0': 0.7875354107648725, '((0, 0, 0, 0), (1, 0, 0, 0))|1': 0.7970749542961609, '((0, 1, 1, 0), (0, 0, 0, 1))|0': 0.22007042253521128, '((0, 1, 1, 0), (0, 0, 0, 1))|1': 0.23376623376623376, '((0, 0, 1, 1), (1, 1, 0, 1))|0': 0.6927710843373494, '((0, 0, 1, 1), (1, 1, 0, 1))|1': 0.7327188940092166, '((0, 0, 0, 0), (0, 0, 0, 1))|0': 0.7439862542955327, '((0, 0, 0, 0), (0, 0, 0, 1))|1': 0.7783251231527094, '((1, 1, 0, 1), (1, 0, 1, 1))|0': 0.47544642857142855, '((1, 1, 0, 1), (1, 0, 1, 1))|1': 0.5121681415929203}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0


### RESULTS
- Predicted under pi_1 (simulated): 0.0056 (var=0.0001)
- Predicted under pi_2 (simulated): 0.0018 (var=0.0003)
- Observed on real data: 0.0105 (var=0.0002)

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
  "interpretation": "Both Tallying (THEORY 1) and WADD (THEORY 2) fail to perfectly capture the observed data, as evidenced by the high observed divergence metrics compared to their simulated self-divergences. However, the data likely reflects a different decision strategy not captured by either equal-weight integration or fully compensatory weighted integration. A classic alternative in this domain is a non-compensatory lexicographic heuristic, which may better explain the choice patterns without requiring full integration of all cues.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Propose the Take-The-Best (TTB) heuristic. In this theory, decision-makers rank the features by their validity and evaluate them sequentially. They stop at the first feature that discriminates between the two options and choose the option favored by that feature, ignoring all remaining features. If no features discriminate, they guess. This introduces a non-compensatory, rank-based approach that strongly contrasts with both the equal-weight exhaustive search of Tallying and the compensatory integration of WADD."
}
```

## Usage

```json
{
  "prompt_token_count": 7771,
  "candidates_token_count": 241,
  "total_token_count": 9282
}
```
