# Round 1 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** Count-Gated Markedness Minimization theory: decision makers do not automatically interpret a binary 1 as a benefit. Instead, they can adopt a stable markedness schema in which 1 denotes a defect, burden, or potentially misleading positive claim. They first compare the number of marked features and prefer the option with fewer marks, with larger count differences producing stronger preferences. Validity is deliberately ignored at this primary stage. Only when marked counts tie do they consult the highest-validity discriminating feature, treating the option marked on that feature as worse. A subject-level defect-schema-strength parameter represents stable conviction that the task's marked state is adverse rather than an arbitrary free sign; residual activation of the conventional benefit schema produces structured polarity uncertainty. Choice precision and occasional lapses add response variability. The theory predicts that complement-coding the stimuli or explicitly defining 1 as beneficial rather than defective should systematically reverse its choices.

**Rationale:** The model directly addresses both failures of Take The Best. In Experiment 1, conflict trials generally place fewer marked features on the TTB-designated option, so the primary count-minimization stage yields relatively high TTB agreement. On tally ties, the highest-validity discriminating mark is treated as a liability, making the tie-break systematically anti-TTB. This produces the required negative difference between tie and conflict alignment rather than TTB's near-zero contrast or Tallying's positive contrast. In Experiment 2 the marked counts are equal, so the reversed-polarity validity tie-break produces alignment below the metric's threshold and therefore predicts zero. Subject-level schema strength and separate count and tie-break precision can generate substantial heterogeneity without permitting an unconstrained polarity sign: every sampled subject remains more committed to the defect interpretation than to the conventional benefit interpretation. Unlike a retuned TTB model, the proposal also makes an experiment-invariant representational prediction: explicitly changing whether 1 means a benefit or a defect, or complement-coding all features, should reverse the markedness component of choice.

**Parameters:**
  - `validities`: `validities`
  - `count_precision`: `[0.8, 2.4]`
  - `validity_tiebreak_precision`: `[0.8, 2.4]`
  - `defect_schema_strength`: `[0.6, 1.0]`
  - `lapse_rate`: `[0.0, 0.05]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Count-Gated Markedness Minimization expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    count_delta = float(np.sum(a) - np.sum(b))

    if count_delta != 0.0:
        # Positive evidence means A carries greater marked-state burden,
        # and therefore supports choosing B. Validity cannot override a
        # difference in the primary marked-feature count.
        evidence_for_b = float(parameters["count_precision"]) * count_delta
    else:
        # On a count tie, inspect the most valid discriminating feature.
        # A mark on that cue is treated as a defect, reversing the usual
        # positive-polarity Take-The-Best interpretation.
        differing = np.flatnonzero(a != b)
        if differing.size == 0:
            return np.array([0.5, 0.5], dtype=float)
        order = differing[np.argsort(-validities[differing], kind="stable")]
        j = int(order[0])
        marked_delta = float(a[j] - b[j])
        evidence_for_b = (
            float(parameters["validity_tiebreak_precision"]) * marked_delta
        )

    # Symmetric logits make positive evidence favor B under the defect
    # schema. Stable schema strength mixes this representation with the
    # residual conventional representation in which a mark is beneficial.
    defect_logits = np.array(
        [-0.5 * evidence_for_b, 0.5 * evidence_for_b], dtype=float
    )
    defect_logits = defect_logits - np.max(defect_logits)
    p_defect = np.exp(defect_logits)
    p_defect /= p_defect.sum()

    schema_strength = float(parameters["defect_schema_strength"])
    p_benefit = p_defect[::-1]
    p_core = schema_strength * p_defect + (1.0 - schema_strength) * p_benefit

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * p_core + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return probs
```

**`policy(probs)`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    probs /= probs.sum()
    return int(np.random.choice(len(probs), p=probs))
```


### slot 2 — `pi_2` — KILLED ✗

**Description:** People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


**Rationale:** (none)

**Parameters:**
  - `beta`: `[0.1, 20.0]`
  - `epsilon`: `[0.0, 0.5]`

**`predict(parameters, stimulus, history)`:**
```python
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
```

**`policy(probs)`:**
```python
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)
```


## Replacement

### `pi_4` → slot 2 (via `new_theory`)

**Description:** Semantic-Polarity Smooth Integration theory: people first interpret what the marked binary state means rather than assuming that 1 is intrinsically desirable. Each subject forms a stable posterior belief that a mark is adverse or suspicious. Conditional on either the adverse interpretation or its residual beneficial alternative, the subject smoothly integrates two continuous signals: the difference in total marks and a partially count-residualized validity-weighted difference. The count signal normally dominates, while the weighted signal supplies graded sensitivity to which experts carry the marks on every trial. The two semantic interpretations generate opposite choice distributions, which are averaged according to the subject's polarity confidence. A small lapse process captures stimulus-independent errors.

**Rationale:** This is a minimal edit to the accepted iteration-2 model. The raw validity signal is only partially, rather than fully, residualized against total count by subtracting 10–30% of mean validity. This preserves the count component whose complete removal caused the rejected iteration-4 deterioration, while modestly reducing the excessive effective count strength responsible for Experiment 4's overly negative prediction. The count-weight range is raised only slightly to help retain the Experiment 1 and large-margin Experiment 3 effects. Sampling partial centering per subject also introduces targeted heterogeneity in the count-to-validity tradeoff without globally increasing lapse or weakening adverse polarity. Validity remains continuous on all trials, so the edit does not introduce a count gate.

**Parameters:**
  - `validities`: `validities`
  - `count_weight`: `[0.38, 1.05]`
  - `validity_weight`: `[0.7, 1.8]`
  - `partial_centering`: `[0.1, 0.3]`
  - `adverse_polarity_confidence`: `[0.78, 1.0]`
  - `lapse_rate`: `[0.0, 0.12]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Semantic-Polarity Smooth Integration expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    # Positive differences mean that A contains more marked states than B.
    count_difference = float(np.sum(a - b))
    partial_centering = float(parameters["partial_centering"])
    effective_validities = validities - partial_centering * float(np.mean(validities))
    weighted_difference = float(np.dot(effective_validities, a - b))

    # There is no count gate: validity contributes continuously on every
    # discriminating trial. Partial centering limits the count component
    # embedded in the weighted sum without removing it completely.
    integrated_markedness = (
        float(parameters["count_weight"]) * count_difference
        + float(parameters["validity_weight"]) * weighted_difference
    )

    adverse_logits = np.array(
        [-0.5 * integrated_markedness, 0.5 * integrated_markedness],
        dtype=float,
    )
    adverse_logits = adverse_logits - np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    # The beneficial interpretation reverses the semantic polarity while
    # preserving the same smooth evidence-integration computation.
    beneficial_probs = adverse_probs[::-1]
    polarity_confidence = float(parameters["adverse_polarity_confidence"])
    core_probs = (
        polarity_confidence * adverse_probs
        + (1.0 - polarity_confidence) * beneficial_probs
    )

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=float)
    return probs / total
```

**`policy(probs)`:**
```python
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / len(probs)
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```
