# Round 2 — Theories

**Verdict:** `new_theory` (slot 1 replaced)

## Starting theories

### slot 1 — `pi_3` — KILLED ✗

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


### slot 2 — `pi_4` — SURVIVED ✓

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


## Replacement

### `pi_5` → slot 1 (via `new_theory`)

**Description:** Discrepancy-Evoked Residual Audit with Capacity-Limited Tie Escalation: people first form an adverse-markedness preference from a nonlinear count difference, while count-residualized validity information remains continuously available. Count discrepancies evoke an additional validity audit, but exact count ties trigger a distinct escalation because tallying provides no provisional winner. This tie escalation is strongest when the cue set fits within a fixed attentional capacity and rapidly dilutes as the number of cues exceeds that capacity. Stable subject differences in tie escalation complement existing differences in count reliance, discrepancy auditing, semantic polarity, precision, and lapses.

**Rationale:** This is a minimal extension of the accepted candidate: it adds only a tie-specific validity bonus and its parameter, leaving every accepted count branch, the continuous validity floor, the discrepancy audit, and the response process unchanged. The bonus acts only when counts tie, so it can reduce Experiment 1's excessive tie alignment without altering its conflict trials or Experiment 5's already accurate one-mark sensitivity. A fixed seven-cue attentional-capacity rule makes the same cognitive mechanism strong in Experiment 1's compact seven-cue display but attenuates it by exp(-4) in Experiment 6's eleven-cue display, protecting the latter's current approximately 0.11 slope. The wide, mean-centered tie-bonus range adds stable subject heterogeneity specifically to the deficient tie-processing channel without repeating rejected broad changes to polarity, precision, or lapse. Experiments 3 and 4 should remain protected because their scored trials are non-ties and all previously accepted count-margin parameters are unchanged.

**Parameters:**
  - `validities`: `validities`
  - `count_strength`: `[2.1, 3.5]`
  - `count_scale`: `[1.2, 2.0]`
  - `small_margin_attenuation`: `[0.72, 0.92]`
  - `intermediate_count_reinforcement`: `[1.6, 3.4]`
  - `extreme_count_tail`: `[1.0, 2.8]`
  - `baseline_validity_gain`: `[0.38, 0.88]`
  - `tie_validity_bonus`: `[0.05, 1.05]`
  - `audit_gain`: `[0.9, 1.6]`
  - `audit_decay`: `[0.7, 1.4]`
  - `margin_three_audit_gain`: `[0.0, 0.1]`
  - `response_precision`: `[0.75, 1.4]`
  - `adverse_polarity_confidence`: `[0.74, 1.0]`
  - `lapse_rate`: `[0.0, 0.15]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Discrepancy-Evoked Residual Audit expects shape "
            f"(2, n_features); got {stim.shape}."
        )

    a, b = stim[0], stim[1]
    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    difference = a - b
    count_difference = float(np.sum(difference))
    margin = abs(count_difference)

    # A bounded provisional tally prevents the strength of the count signal
    # from growing without limit as experiments add more features.
    count_scale = float(parameters["count_scale"])
    count_signal = float(parameters["count_strength"]) * np.tanh(
        count_difference / count_scale
    )

    # Small discrepancies leave the provisional tally relatively uncertain.
    # This redistributes count strength away from margins one and two without
    # weakening the separately reinforced moderate and extreme branches.
    if 0.0 < margin <= 2.0:
        count_signal *= float(parameters["small_margin_attenuation"])

    # Reinforce moderate discrepancies without changing margin-one or
    # margin-two behavior and without adding growth to the extreme branch.
    if 3.0 <= margin < 5.0:
        count_signal += (
            float(parameters["intermediate_count_reinforcement"])
            * float(np.sign(count_difference))
        )

    # Selectively reinforce only decisive margins, leaving small- and
    # moderate-margin behavior otherwise unchanged.
    if margin >= 5.0:
        extreme_activation = np.tanh(max(0.0, margin - 4.0))
        count_signal += (
            float(parameters["extreme_count_tail"])
            * float(np.sign(count_difference))
            * extreme_activation
        )

    # Centering cue validity removes the component of weighted evidence that
    # simply restates which option has more marks. The remaining signal asks
    # whether an option's marks are carried by unusually reliable experts.
    centered_validities = validities - float(np.mean(validities))
    residual_validity = float(np.dot(centered_validities, difference))

    # Validity is always available through baseline_validity_gain. A count
    # discrepancy evokes an extra audit, maximal at a one-mark margin and
    # progressively suppressed when the count margin is already decisive.
    baseline_gain = float(parameters["baseline_validity_gain"])
    audit_gain = float(parameters["audit_gain"])
    audit_decay = float(parameters["audit_decay"])
    if margin > 0.0:
        discrepancy_activation = margin * np.exp(
            -audit_decay * max(0.0, margin - 1.0)
        )
    else:
        discrepancy_activation = 0.0
    validity_gain = baseline_gain + audit_gain * discrepancy_activation

    # When tallying supplies no provisional winner, validity inspection is
    # escalated. The escalation is diluted beyond a seven-cue attentional
    # capacity, separating compact tie problems from large cue arrays while
    # retaining the nonzero validity floor in every task.
    if np.isclose(margin, 0.0):
        tie_capacity = np.exp(-max(0.0, float(n_features) - 7.0))
        validity_gain += float(parameters["tie_validity_bonus"]) * tie_capacity

    # A small, structurally localized audit may be elicited at margin three.
    # Its reduced range prevents it from counteracting moderate count evidence.
    if np.isclose(margin, 3.0):
        validity_gain += float(parameters["margin_three_audit_gain"])

    markedness_evidence = count_signal + validity_gain * residual_validity
    markedness_evidence *= float(parameters["response_precision"])

    # Positive evidence means A carries the greater adverse burden and hence
    # favors B. The alternative semantic interpretation reverses all evidence,
    # and stable polarity confidence mixes the two interpretations.
    adverse_logits = np.array(
        [-0.5 * markedness_evidence, 0.5 * markedness_evidence], dtype=float
    )
    adverse_logits -= np.max(adverse_logits)
    adverse_probs = np.exp(adverse_logits)
    adverse_probs /= adverse_probs.sum()

    beneficial_probs = adverse_probs[::-1]
    polarity = float(parameters["adverse_polarity_confidence"])
    core_probs = polarity * adverse_probs + (1.0 - polarity) * beneficial_probs

    lapse = float(parameters["lapse_rate"])
    probs = (1.0 - lapse) * core_probs + lapse * np.array([0.5, 0.5])
    probs = np.asarray(probs, dtype=np.float64)
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
