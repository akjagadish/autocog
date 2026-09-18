# Round 4 — Theories

**Verdict:** `new_theory` (slot 2 replaced)

## Starting theories

### slot 1 — `pi_3` — SURVIVED ✓

**Description:** Recency-Gated Reason Overwrite with Processing Fatigue. People inspect cues sequentially in descending order of instructed validity and continue after finding a discriminating cue. An attended discriminating cue establishes a provisional choice, and each subsequently attended discriminating cue can overwrite that choice. Consequently, the final attended reason has disproportionate control. Occasional failures to attend a cue preserve an earlier reason, while response lapses dilute strong recency effects. In addition, processing more than two discriminating reasons produces task-invariant update fatigue: the retained decision is expressed with progressively lower reliability as the discriminating-cue count increases. This preserves strong second-reason overwrite on short conflicts while moderating near-deterministic last-reason control on longer sequences.

**Rationale:** This is a minimal extension of the accepted recency-overwrite model. The cue scan and overwrite equations are unchanged. The only mechanistic addition is a discriminating-cue-count fatigue gate that begins after the second reason, together with a broader and slightly lower lapse range. Two-reason trials therefore retain the strong overwrite needed for Experiment 2, whereas long reason sequences are pulled modestly toward uncertainty, reducing the excessive Experiment-1 contrast. Lower average lapse simultaneously strengthens anti-TTB behavior in Experiment 2. Broad subject-level ranges for fatigue and lapse should also increase the previously underestimated between-subject variability. The gate is task-invariant and depends only on processing load, not experiment identity or stimulus-specific switches.

**Parameters:**
  - `validities`: `validities`
  - `cue_attention`: `[0.95, 1.0]`
  - `overwrite_rate`: `[0.95, 1.0]`
  - `update_fatigue`: `[0.06, 0.17]`
  - `lapse_rate`: `[0.15, 0.41]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Recency-Gated Reason Overwrite expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    attention = float(parameters["cue_attention"])
    overwrite = float(parameters["overwrite_rate"])
    fatigue = float(parameters["update_fatigue"])
    lapse = float(parameters["lapse_rate"])

    # Stable sorting represents the displayed high-to-low validity scan;
    # ties retain their display order.
    cue_order = np.argsort(-validities, kind="stable")
    diff = stim[0] - stim[1]

    # Exact marginal distribution over the provisional state:
    # A selected, B selected, or no discriminating cue encoded yet.
    p_a, p_b, p_uncommitted = 0.0, 0.0, 1.0
    discriminating_count = 0

    for j in cue_order:
        direction = diff[j]
        if direction == 0:
            continue

        discriminating_count += 1
        old_a, old_b, old_u = p_a, p_b, p_uncommitted

        if direction > 0:
            # An attended A cue initializes an uncommitted decision and
            # overwrites a conflicting B decision with the overwrite rate.
            p_a = old_a + attention * overwrite * old_b + attention * old_u
            p_b = old_b * (1.0 - attention * overwrite)
            p_uncommitted = old_u * (1.0 - attention)
        else:
            p_b = old_b + attention * overwrite * old_a + attention * old_u
            p_a = old_a * (1.0 - attention * overwrite)
            p_uncommitted = old_u * (1.0 - attention)

    # If no discriminating cue was encoded, either response is an equal guess.
    p_core = np.array([
        p_a + 0.5 * p_uncommitted,
        p_b + 0.5 * p_uncommitted
    ], dtype=np.float64)

    # Processing the first reason and its immediate successor is reliable.
    # Additional discriminating updates progressively weaken expression of
    # the retained choice without disrupting the crucial second-cue reversal.
    excess_updates = max(0, discriminating_count - 2)
    retention = (1.0 - fatigue) ** excess_updates
    p_core = retention * p_core + (1.0 - retention) * np.array([0.5, 0.5])

    # Independent execution/inattention lapse.
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


### slot 2 — `pi_6` — KILLED ✗

**Description:** Validity-Ordered Competitive Evidence Buffer with Conflict-Normalized Readout. Decision makers inspect cues in descending order of instructed validity and encode every discriminating cue as signed evidence rather than as a provisional choice or directional chunk. Each newly encoded reason causes graded displacement of all earlier traces in a capacity-limited working-memory buffer. Displacement becomes stronger as the buffer exceeds its stable subject-specific capacity, but old evidence is never categorically erased. At response, the decision maker sums all surviving validity-scaled traces. Readout normalization depends on the balance of accessible evidence: it is strongest when substantial trace mass supports both options and weak when the accessible buffer contains a coherent majority. Readout uncertainty additionally grows quadratically with capacity overload and receives a count-based attenuation beginning explicitly at seven discriminating reasons, contracting long conflicts toward chance without imposing arrangement-specific effects. Stable individual differences in effective capacity, displacement rate, validity sensitivity, response gain, and conflict normalization generate heterogeneous recency and integration behavior.

**Rationale:** This is a one-line calibration edit to the accepted iteration-9 model: the response_gain range is broadened downward from [3.0, 6.5] to [2.0, 6.5]. All trace encoding, validity-ranked inspection, displacement, capacity overload, conflict-sensitive normalization, and seven-plus uncertainty equations remain unchanged. The lower mean gain provides the modest contraction toward chance jointly indicated by Experiments 1, 2, 3, 4, and 6: it should reduce excessive tally and terminal effects while raising the currently underpredicted below-chance rates in Experiments 2 and 6. The added low-gain subjects also provide a direct source of stable response-expression heterogeneity, especially around the four-reason conflict in Experiment 4, without reopening validity or displacement heterogeneity. Retaining the previous upper bound preserves strongly recency-controlled individuals, while the accepted conflict-sensitive normalization continues to protect coherent anti-terminal majorities in Experiment 8 better than a generic increase in normalization would. No run, suffix, switch-density, display-position, or categorical-overwrite mechanism is introduced.

**Parameters:**
  - `validities`: `validities`
  - `buffer_capacity`: `[3.0, 3.8]`
  - `displacement_rate`: `[2.1, 2.9]`
  - `validity_sensitivity`: `[0.0, 0.08]`
  - `response_gain`: `[2.0, 6.5]`
  - `integration_normalization`: `[0.02, 0.34]`
  - `overflow_noise`: `[0.75, 1.50]`
  - `lapse_rate`: `[0.03, 0.15]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Competitive evidence buffer expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    capacity = float(parameters["buffer_capacity"])
    displacement = float(parameters["displacement_rate"])
    validity_sensitivity = float(parameters["validity_sensitivity"])
    response_gain = float(parameters["response_gain"])
    integration_normalization = float(parameters["integration_normalization"])
    overflow_noise = float(parameters["overflow_noise"])
    lapse = float(parameters["lapse_rate"])

    diff = stim[0] - stim[1]

    # Inspection follows instructed validity, independently of physical
    # feature position. Stable sorting only resolves exact validity ties.
    cue_order = np.argsort(-validities, kind="stable")
    discriminating = [int(j) for j in cue_order if diff[j] != 0]
    m = len(discriminating)
    if m == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    # Convert instructed reliability into evidence strength. Normalization
    # removes arbitrary differences in the overall validity scale between
    # experiments while preserving all within-experiment validity ratios.
    clipped_v = np.clip(validities, 0.5001, 0.999)
    reliability = np.log(clipped_v / (1.0 - clipped_v))
    positive_reliability = reliability[reliability > 0.0]
    reliability_scale = float(np.mean(positive_reliability))
    if not np.isfinite(reliability_scale) or reliability_scale <= 0.0:
        reliability_scale = 1.0

    normalized_reliability = np.clip(reliability / reliability_scale, 1e-4, 20.0)
    cue_strength = np.power(normalized_reliability, validity_sensitivity)
    cue_strength = np.clip(cue_strength, 1e-6, 30.0)

    # The buffer contains separate reason traces. A new discriminating reason
    # interferes continuously with every old trace. Displacement is present
    # even below capacity and increases smoothly under overload; there is no
    # categorical slot deletion and no compression into directional runs.
    traces = []
    for j in discriminating:
        current_load = float(len(traces))
        overload_before_entry = max(0.0, current_load + 1.0 - capacity)
        load_factor = 1.0 + overload_before_entry / max(capacity, 1e-6)
        retention = np.exp(-displacement * load_factor / max(capacity, 1e-6))
        retention = float(np.clip(retention, 0.0, 1.0))

        if traces:
            traces = [retention * trace for trace in traces]

        direction = float(np.sign(diff[j]))  # positive favors A
        traces.append(direction * float(cue_strength[j]))

    accessible_evidence = float(np.sum(traces))

    # Preserve the accepted quadratic capacity-overload uncertainty through
    # six reasons. Beginning explicitly at seven discriminating reasons, add
    # a modest count-based attenuation that is not smeared by capacity.
    overflow = max(0.0, float(m) - capacity)
    long_sequence_excess = max(0.0, float(m) - 6.0)
    convex_multiplier = 1.0 + 0.45 * long_sequence_excess
    readout_sd = np.sqrt(
        1.0 + overflow_noise * overflow * overflow * convex_multiplier
    )

    # Normalize integrated evidence only when accessible traces substantially
    # support both options. Squaring the balance ratio leaves coherent
    # majorities largely intact. The effect remains absent for two reasons.
    positive_mass = float(np.sum([trace for trace in traces if trace > 0.0]))
    negative_mass = float(-np.sum([trace for trace in traces if trace < 0.0]))
    total_mass = positive_mass + negative_mass
    if m <= 2 or total_mass <= 0.0 or not np.isfinite(total_mass):
        conflict_load = 0.0
    else:
        balance = 2.0 * min(positive_mass, negative_mass) / total_mass
        balance = float(np.clip(balance, 0.0, 1.0))
        conflict_load = np.sqrt(max(0.0, float(m) - 2.0)) * balance * balance
    integration_divisor = 1.0 + integration_normalization * conflict_load

    decision_variable = (
        response_gain * accessible_evidence
        / (readout_sd * integration_divisor)
    )
    decision_variable = float(np.clip(decision_variable, -60.0, 60.0))

    p_a_core = 1.0 / (1.0 + np.exp(-decision_variable))
    p_core = np.array([p_a_core, 1.0 - p_a_core], dtype=np.float64)

    probs = (1.0 - lapse) * p_core + lapse * np.array([0.5, 0.5])
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
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

### `pi_7` → slot 2 (via `new_theory`)

**Description:** Load-Contingent Dual-Code Arbitration. While inspecting discriminating experts in instructed-validity order, a decision maker constructs two qualitatively different codes. The local code is a rapidly revised categorical commitment: each new discriminating reason almost completely replaces the previous commitment, so reasons outside the recent suffix become functionally absent rather than merely weakened traces. In parallel, the person can form a validity-weighted global coalition summary that preserves cumulative directional evidence without preserving cue order. Choice is governed by smooth arbitration between these codes. Global comparison is recruited only after conflict is sufficiently elaborate to warrant comparison, is favored when validity-weighted evidence forms a diagnostic coalition supported by an unweighted directional majority, and loses accessibility when subject-specific effective capacity is exceeded. Coalition selectivity is itself load-contingent: a coalition must be especially strong near the recruitment boundary, whereas weaker cumulative coalitions become usable inside the subject's manageable comparison window before becoming inaccessible under overload. Within that manageable window, global control receives a selective increment when the global coalition opposes the current local commitment, because only such disagreement warrants effortful comparison. Thus short or count-balanced conflicts are dominated by local revision, manageable majority-coalition conflicts can be decided cumulatively, and overloaded conflicts revert toward an uncertainty-attenuated recent commitment. Capacity, recruitment threshold, coalition selectivity, and local and global gains are stable subject characteristics shared across trials.

**Rationale:** This is a minimal edit to the accepted candidate. The recruitment-threshold range is shifted modestly upward from [2.8, 3.8] to [3.1, 4.0], reducing validity-weighted global leakage at the three-reason boundary relevant to Experiment 9 while leaving five- and six-reason conflicts above recruitment. The additive opposition coefficient is increased from 0.45 to 0.95, but the increment now contains accessibility squared. This gives stronger disagreement-contingent global reversal inside the manageable window, targeting the excessive terminal agreement in Experiments 3 and 8, while causing the increment to decay more rapidly once load approaches or exceeds capacity, protecting Experiment 6. Count-balanced protection, nonsaturating count diagnosticity, categorical local revision, global gain, and all other equations and ranges are unchanged.

**Parameters:**
  - `validities`: `validities`
  - `effective_capacity`: `[5.8, 6.8]`
  - `recruitment_threshold`: `[3.1, 4.0]`
  - `arbitration_temperature`: `[0.35, 0.75]`
  - `local_retention`: `[0.0, 0.04]`
  - `local_gain`: `[1.35, 2.15]`
  - `global_gain`: `[2.0, 4.2]`
  - `validity_sensitivity`: `[0.65, 1.35]`
  - `coalition_focus`: `[0.75, 1.65]`
  - `overload_attenuation`: `[0.8, 1.6]`
  - `lapse_rate`: `[0.03, 0.14]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Dual-code arbitration expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    capacity = float(parameters["effective_capacity"])
    recruitment_threshold = float(parameters["recruitment_threshold"])
    arbitration_temperature = float(parameters["arbitration_temperature"])
    local_retention = float(parameters["local_retention"])
    local_gain = float(parameters["local_gain"])
    global_gain = float(parameters["global_gain"])
    validity_sensitivity = float(parameters["validity_sensitivity"])
    coalition_focus = float(parameters["coalition_focus"])
    overload_attenuation = float(parameters["overload_attenuation"])
    lapse = float(parameters["lapse_rate"])

    diff = stim[0] - stim[1]
    cue_order = np.argsort(-validities, kind="stable")
    discriminating = [int(j) for j in cue_order if diff[j] != 0]
    m = len(discriminating)
    if m == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    directions = np.asarray(
        [float(np.sign(diff[j])) for j in discriminating], dtype=float
    )

    # LOCAL CODE: a categorical commitment rather than a common evidence
    # buffer. Every newly encoded reason installs its own direction and only
    # a small residue of the immediately preceding commitment remains.
    # Consequently, sufficiently early reasons are functionally absent.
    local_commitment = 0.0
    for direction in directions:
        local_commitment = direction + local_retention * local_commitment
    local_commitment = float(np.clip(local_commitment, -1.5, 1.5))

    # GLOBAL CODE: cumulative validity-weighted coalition evidence. Log odds
    # represent communicated reliability, while normalization makes the code
    # portable across experiments with different absolute validity scales.
    v = np.clip(validities[discriminating], 0.5001, 0.999)
    reliability = np.log(v / (1.0 - v))
    positive = reliability[reliability > 0.0]
    scale = float(np.mean(positive)) if positive.size else 1.0
    if not np.isfinite(scale) or scale <= 0.0:
        scale = 1.0
    weights = np.power(
        np.clip(reliability / scale, 1e-4, 20.0), validity_sensitivity
    )
    weights = np.clip(weights, 1e-5, 30.0)

    signed_global = float(np.sum(weights * directions))
    global_norm = float(np.sqrt(np.sum(weights * weights)))
    if not np.isfinite(global_norm) or global_norm <= 0.0:
        global_norm = 1.0
    global_summary = signed_global / global_norm

    total_weight = float(np.sum(weights))
    coalition_strength = abs(signed_global) / max(total_weight, 1e-9)
    coalition_strength = float(np.clip(coalition_strength, 0.0, 1.0))

    # Conflict balance is high when both options have several reasons. It is
    # arrangement-free: only directional masses enter, never switch counts or
    # directional runs.
    positive_mass = float(np.sum(weights[directions > 0.0]))
    negative_mass = float(np.sum(weights[directions < 0.0]))
    if positive_mass + negative_mass <= 0.0:
        conflict_balance = 0.0
    else:
        conflict_balance = (
            2.0 * min(positive_mass, negative_mass)
            / (positive_mass + negative_mass)
        )
    conflict_balance = float(np.clip(conflict_balance, 0.0, 1.0))

    temp = max(arbitration_temperature, 1e-6)

    # Recruitment rises smoothly once a conflict warrants an explicit global
    # comparison, but global accessibility falls smoothly near the person's
    # effective capacity. No fixed cue-count boundary is imposed.
    onset_x = np.clip((float(m) - recruitment_threshold) / temp, -60.0, 60.0)
    onset = 1.0 / (1.0 + np.exp(-onset_x))
    capacity_x = np.clip((capacity - float(m)) / temp, -60.0, 60.0)
    accessibility = 1.0 / (1.0 + np.exp(-capacity_x))

    # Validity weighting determines the content of the global summary, but
    # recruitment also requires an unweighted directional coalition. A
    # smooth, nonsaturating transform gives a one-vote majority only partial
    # diagnosticity, while preserving exact protection for count balance and
    # approaching full support only for genuinely lopsided coalitions.
    raw_count_coalition = abs(float(np.sum(directions))) / float(m)
    raw_count_coalition = float(np.clip(raw_count_coalition, 0.0, 1.0))
    count_coalition = (
        (1.0 - np.exp(-2.0 * raw_count_coalition))
        / (1.0 - np.exp(-2.0))
    )
    count_coalition = float(np.clip(count_coalition, 0.0, 1.0))

    # Coalition selectivity varies smoothly with effective load. Near the
    # subject's recruitment boundary, only a strong weighted coalition can
    # engage global comparison. Once load is clearly above that boundary but
    # still below effective capacity, weaker cumulative coalitions become
    # usable. Selectivity tightens again as overload approaches. The window is
    # defined relative to stable subject-specific thresholds rather than by a
    # fixed number of cues.
    comparison_x = np.clip(
        (float(m) - recruitment_threshold - 0.75) / temp, -60.0, 60.0
    )
    comparison_ready = 1.0 / (1.0 + np.exp(-comparison_x))
    pre_overload_x = np.clip(
        (capacity + 0.50 - float(m)) / temp, -60.0, 60.0
    )
    pre_overload_access = 1.0 / (1.0 + np.exp(-pre_overload_x))
    manageable_window = comparison_ready * pre_overload_access
    selectivity_cutoff = 0.56 - 0.30 * manageable_window

    weighted_selectivity_x = np.clip(
        (coalition_strength - selectivity_cutoff) / 0.12, -60.0, 60.0
    )
    weighted_selectivity = 1.0 / (1.0 + np.exp(-weighted_selectivity_x))
    diagnosticity = np.power(
        np.clip(coalition_strength, 0.0, 1.0), coalition_focus
    )
    diagnosticity *= count_coalition * weighted_selectivity
    diagnosticity = float(np.clip(diagnosticity, 0.0, 1.0))

    global_gate = float(np.clip(onset * accessibility * diagnosticity, 0.0, 1.0))

    # Effortful global arbitration is selectively useful when its cumulative
    # conclusion opposes the current local commitment. A bounded additive
    # increment can rescue a weak baseline gate inside the manageable window,
    # while count support, weighted selectivity, and accessibility suppress it
    # near recruitment, in balanced displays, and under overload.
    code_opposition = 0.5 * (
        1.0 - np.tanh(local_commitment * global_summary / 0.20)
    )
    opposition_window = manageable_window * manageable_window * pre_overload_access
    opposition_increment = (
        0.95
        * accessibility
        * accessibility
        * opposition_window
        * code_opposition
        * count_coalition
        * weighted_selectivity
    )
    global_gate += opposition_increment
    global_gate = float(np.clip(global_gate, 0.0, 1.0))

    # Capacity pressure attenuates expression of the local commitment. Its
    # smooth onset slightly precedes nominal capacity, reflecting the cost of
    # maintaining both codes before capacity is completely exceeded.
    overload = temp * np.logaddexp(
        0.0, (float(m) - capacity + 0.75) / temp
    )
    local_divisor = np.sqrt(1.0 + overload_attenuation * overload * overload)
    local_dv = local_gain * local_commitment / local_divisor
    global_dv = global_gain * global_summary

    decision_variable = (
        (1.0 - global_gate) * local_dv + global_gate * global_dv
    )
    decision_variable = float(np.clip(decision_variable, -60.0, 60.0))

    p_a = 1.0 / (1.0 + np.exp(-decision_variable))
    core = np.array([p_a, 1.0 - p_a], dtype=np.float64)
    probs = (1.0 - lapse) * core + lapse * np.array([0.5, 0.5])

    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        return np.array([0.5, 0.5], dtype=np.float64)
    return probs / total
```

**`policy(probs)`:**
```python
def policy(probs) -> int:
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    total = float(probs.sum())
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / len(probs)
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```
