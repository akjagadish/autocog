# Round 2 — Theories

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


### slot 2 — `pi_4` — KILLED ✗

**Description:** Interference-Limited Retrospective Reason Sampling with Length-Calibrated Accessibility. After viewing all cues, a decision maker retrospectively retrieves one or, subject to stable working-memory capacity, occasionally two discriminating reasons. In two-reason conflicts, retrieval has a strong saturated terminal-recency floor, producing reliable last-reason capture without importing subject heterogeneity from longer conflicts. Around four reasons, stable variation in recency remains expressed. When conflicts exceed four reasons, nonlinear source interference flattens recency while accessibility approaches a validity-biased rather than uniform asymptote. Choice follows the signed, validity-sensitive evidence supplied by the retrieved reasons, with a small response lapse.

**Rationale:** This is a minimal accessibility edit to the accepted model. First, two-cue conflicts receive a strong but saturated recency gradient. This should lower Experiment 2 first-cue agreement and its between-subject variance without narrowing the broad recency distribution responsible for Experiment 4's accurately reproduced heterogeneity. Second, overload now selectively increases validity-based accessibility while cubic interference continues to suppress temporal recency. Long conflicts therefore approach validity-biased retrieval rather than uniform, tally-like sampling, which should reduce Experiment 1's excessive TTB–tally contrast. The capacity limit, four-cue recency regime, evidence mapping, continuation mechanism, lapse, and all parameter ranges are otherwise unchanged.

**Parameters:**
  - `validities`: `validities`
  - `memory_capacity`: `{1, 2}`
  - `recency_bias`: `[0.2, 4.6]`
  - `validity_access`: `[0.05, 0.35]`
  - `interference_rate`: `[0.6, 1.4]`
  - `second_reason_rate`: `[0.02, 0.12]`
  - `evidence_floor`: `[0.35, 0.75]`
  - `evidence_gain`: `[3.0, 7.0]`
  - `lapse_rate`: `[0.03, 0.17]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Retrospective reason sampling expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    capacity = int(parameters["memory_capacity"])
    recency = float(parameters["recency_bias"])
    validity_access = float(parameters["validity_access"])
    interference = float(parameters["interference_rate"])
    continuation = float(parameters["second_reason_rate"])
    evidence_floor = float(parameters["evidence_floor"])
    evidence_gain = float(parameters["evidence_gain"])
    lapse = float(parameters["lapse_rate"])

    diff = stim[0] - stim[1]
    cue_indices = np.flatnonzero(diff != 0)
    m = int(cue_indices.size)
    if m == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    # Reliability is represented as instructed log-odds. Clipping only
    # prevents infinite evidence for a validity communicated as exactly 1.
    v = np.clip(validities[cue_indices], 0.500001, 0.999)
    reliability = np.log(v / (1.0 - v))
    directions = np.sign(diff[cue_indices])  # +1 favors A, -1 favors B

    # Cues are displayed from highest to lowest validity. Ordinal position
    # among discriminating cues therefore indexes retrospective recency.
    ordinal_recency = np.arange(m, dtype=float)

    # Interference is negligible through four reasons but grows cubically
    # thereafter, rapidly flattening accessibility in long conflicts.
    overload = float(max(0, m - 4))
    effective_recency = recency / (1.0 + interference * overload * overload * overload)

    # A two-reason conflict is represented as a compact terminal episode:
    # its recency gradient is strong and saturates across subjects. Stable
    # recency differences remain fully expressed in four-reason conflicts.
    if m == 2:
        effective_recency = 3.4 + 0.15 * np.tanh(recency - 2.0)

    # Under overload, interference removes temporal-source information but
    # does not make all reasons equally accessible. Retrieval instead tends
    # toward a modestly validity-biased asymptote.
    effective_validity_access = (
        validity_access + 0.55 * overload / (1.0 + overload)
    )

    log_access = (
        effective_recency * ordinal_recency
        + effective_validity_access * reliability
    )
    log_access -= np.max(log_access)
    access = np.exp(log_access)
    first_probs = access / access.sum()

    def probability_a(retrieved_positions):
        # Every retrieved reason supplies substantial directional evidence;
        # instructed validity additionally scales that evidence and resolves
        # conflicts when more than one reason is retrieved.
        positions = list(retrieved_positions)
        evidence = float(np.sum(
            directions[positions]
            * (evidence_floor + reliability[positions])
        ))
        x = float(np.clip(evidence_gain * evidence, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # Exact marginalization over the first retrospectively retrieved reason.
    p_a_one = 0.0
    for i in range(m):
        p_a_one += float(first_probs[i]) * probability_a((i,))

    # Capacity is an upper bound: even capacity-two subjects often terminate
    # retrieval after one sufficient reason. If retrieval continues, the
    # second reason is sampled without replacement from the same accessibility
    # distribution and both reasons are integrated.
    if capacity >= 2 and m >= 2 and continuation > 0.0:
        p_a_two = 0.0
        for i in range(m):
            remaining_mass = float(access.sum() - access[i])
            if remaining_mass <= 0.0:
                continue
            for j in range(m):
                if j == i:
                    continue
                p_ordered = float(first_probs[i]) * float(access[j] / remaining_mass)
                p_a_two += p_ordered * probability_a((i, j))
        p_a_core = (1.0 - continuation) * p_a_one + continuation * p_a_two
    else:
        p_a_core = p_a_one

    p_core = np.array([p_a_core, 1.0 - p_a_core], dtype=np.float64)
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
    total = probs.sum()
    if not np.isfinite(total) or total <= 0.0:
        probs = np.ones(len(probs), dtype=np.float64) / len(probs)
    else:
        probs /= total
    return int(np.random.choice(len(probs), p=probs))
```


## Replacement

### `pi_5` → slot 2 (via `new_theory`)

**Description:** Saturated Directional-Run Chunking with Boundary Interference. People scan discriminating cues in their instructed order and compress consecutive cues favoring the same option into a single directional chunk. Chunk confidence rises rapidly with run length but saturates, so two agreeing terminal cues can be nearly as effective as a much longer terminal run. At each directional boundary, the newly completed chunk suppresses the accumulated representation of earlier chunks. A coherent terminal run receives an additional replacement advantage, causing stimuli with the same strong suffix to converge despite differences in prefix segmentation. Short four-reason sequences preserve run structure at high temporal resolution and express terminal chunks with a heterogeneous gain, producing strong but individually variable terminal control. In longer sequences, switch-dense patterns suffer source interference, while long low-switch conflicts undergo a separate modest loss of response precision without recovering early high-validity cues. Instructed validity only modestly scales chunk encoding and cannot become the retrieval asymptote. Choices arise from recency-weighted competition among run summaries plus a small response lapse.

**Rationale:** This is a two-range calibration of the accepted model; all equations and successful mechanisms are unchanged. The long-low-switch loss is strengthened and widened from [0.05, 0.20] to [0.08, 0.34]. This selectively reduces the overly extreme choices produced by coherent seven-plus-cue conflicts in Experiment 1 and increases subject heterogeneity, while remaining moderate enough to move Experiment 6 only slightly toward chance. Switch interference is increased from [1.5, 2.5] to [1.8, 2.8], adding uncertainty only after more than two directional boundaries and thereby targeting Experiment 3 without weakening the coherent-suffix mechanism responsible for the strong Experiment 5 fit. The four-reason gain, suffix replacement, generic length interference, and validity encoding are preserved to protect the accepted fits in Experiments 2, 4, and 5.

**Parameters:**
  - `validities`: `validities`
  - `run_saturation`: `[1.8, 3.2]`
  - `boundary_suppression`: `[0.35, 0.55]`
  - `chunk_recency_decay`: `[0.78, 0.94]`
  - `short_resolution_boost`: `[0.12, 0.68]`
  - `suffix_replacement`: `[0.08, 0.25]`
  - `four_reason_expression_gain`: `[0.35, 2.60]`
  - `switch_interference`: `[1.8, 2.8]`
  - `length_interference`: `[0.06, 0.12]`
  - `long_low_switch_loss`: `[0.08, 0.34]`
  - `validity_encoding_scale`: `[0.02, 0.20]`
  - `choice_gain`: `[2.6, 3.8]`
  - `lapse_rate`: `[0.04, 0.14]`

**`predict(parameters, stimulus, history)`:**
```python
def predict(parameters, state, history) -> np.ndarray:
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Directional-run chunking expects shape (2, n_features); got {stim.shape}."
        )

    n_features = stim.shape[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    if validities.ndim != 1 or validities.size != n_features:
        raise ValueError(
            f"validities length {validities.size} != n_features {n_features}."
        )

    saturation = float(parameters["run_saturation"])
    suppression = float(parameters["boundary_suppression"])
    recency_decay = float(parameters["chunk_recency_decay"])
    short_boost = float(parameters["short_resolution_boost"])
    suffix_replacement = float(parameters["suffix_replacement"])
    four_gain = float(parameters["four_reason_expression_gain"])
    switch_interference = float(parameters["switch_interference"])
    length_interference = float(parameters["length_interference"])
    long_low_switch_loss = float(parameters["long_low_switch_loss"])
    validity_scale = float(parameters["validity_encoding_scale"])
    choice_gain = float(parameters["choice_gain"])
    lapse = float(parameters["lapse_rate"])

    diff = stim[0] - stim[1]
    cue_indices = np.flatnonzero(diff != 0)
    m = int(cue_indices.size)
    if m == 0:
        return np.array([0.5, 0.5], dtype=np.float64)

    directions = np.sign(diff[cue_indices]).astype(float)
    cue_validities = np.clip(validities[cue_indices], 0.5, 1.0)

    # Validity changes encoding strength only modestly. Every discriminating
    # cue has a substantial baseline representation, preventing overload from
    # turning retrieval into a validity-biased early-cue process.
    encoded_strengths = 1.0 + validity_scale * (2.0 * cue_validities - 1.0)

    # Compress contiguous cues with a common direction into run summaries.
    runs = []
    start = 0
    for i in range(1, m + 1):
        if i == m or directions[i] != directions[start]:
            direction = float(directions[start])
            encoding_mass = float(np.sum(encoded_strengths[start:i]))
            # Repetition increases chunk confidence, but confidence rapidly
            # saturates rather than growing as an unbounded cue tally.
            confidence = 1.0 - np.exp(-saturation * encoding_mass)
            runs.append((direction, confidence, i - start))
            start = i

    n_switches = max(0, len(runs) - 1)

    # Compete run summaries online. A new coherent chunk both enters memory
    # and suppresses prior chunks. Short sequences retain sharper boundary
    # resolution, yielding especially effective terminal replacement.
    directional_memory = 0.0
    represented_mass = 0.0
    for run_number, (direction, confidence, run_length) in enumerate(runs):
        if run_number == 0:
            directional_memory = direction * confidence
            represented_mass = confidence
            continue

        effective_suppression = suppression
        if m <= 4:
            effective_suppression += short_boost
        # A repeated-direction suffix is encoded as a completed terminal
        # decision chunk and therefore more fully replaces prefix summaries.
        if run_number == len(runs) - 1 and run_length >= 2:
            effective_suppression += suffix_replacement
        effective_suppression = float(np.clip(effective_suppression, 0.0, 0.98))

        retention = recency_decay * (1.0 - effective_suppression * confidence)
        retention = float(np.clip(retention, 0.0, 1.0))
        directional_memory = retention * directional_memory + direction * confidence
        represented_mass = retention * represented_mass + confidence

    if represented_mass <= 0.0 or not np.isfinite(represented_mass):
        normalized_direction = 0.0
    else:
        normalized_direction = float(
            np.clip(directional_memory / represented_mass, -1.0, 1.0)
        )

    # Switch-dense sequences lose directional source resolution. Generic
    # length uncertainty remains mild, while long low-switch conflicts have
    # a separate expression loss that attenuates extremity without restoring
    # privileged access to early cues.
    excess_switches = max(0, n_switches - 2)
    low_switch_excess = max(0, m - 5) if n_switches <= 2 else 0
    precision_denominator = (
        1.0
        + switch_interference * float(excess_switches ** 2)
        + length_interference * float(max(0, m - 4))
        + long_low_switch_loss * float(low_switch_excess)
    )
    effective_gain = choice_gain / precision_denominator

    # Four-reason displays preserve unusually high temporal resolution. The
    # broad subject-level gain range captures heterogeneity in expressing the
    # terminal chunk without changing longer conflicts.
    if m == 4:
        effective_gain *= four_gain

    logit_a = float(np.clip(effective_gain * normalized_direction, -60.0, 60.0))
    p_a_core = 1.0 / (1.0 + np.exp(-logit_a))
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
