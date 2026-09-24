# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_11" and "pi_10") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_11" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_10" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_11
People make binary-feature choices by a primary unweighted signed tally. When the full tally is clear, choice follows that tally through a stochastic choice rule with a small lapse. When the tally is near-tied, people parse the advertised validity vector into contiguous coherent runs and resolve the choice with one selected run. Priority goes to coherent terminal segments opened by validity discontinuities, including forced late-triplet openings on short displays; if no usable terminal segment opens, people fall back to the earliest coherent preceding segment. Inside the selected segment all features receive equal weight: validity differences affect only whether a segment is recognized and how decisively its sub-tally drives choice, never the relative cue weights within the segment. Calibration rules make flat, clearly contrasted forced late triplets on very short displays strongly decisive, moderate-jump high-altitude terminal runs on nine-to-ten-cue displays decisive, large-display forced openings and large-display low-altitude fallbacks near chance, and size-six high-altitude terminal runs moderately damped.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    validities = np.asarray(parameters['validities'], dtype=float)
    n = stim.shape[1]
    if validities.shape[0] != n:
        raise ValueError('validities length mismatch.')

    a = stim[0]
    b = stim[1]
    diff = a - b
    tally = float(np.sum(diff))

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        denom = float(np.sum(e))
        if denom <= 1e-12:
            return np.ones_like(scores, dtype=float) / float(len(scores))
        return e / denom

    def lapse_mix(core, eps):
        probs = (1.0 - eps) * core + eps * np.array([0.5, 0.5])
        probs = np.clip(probs, 0.005, 0.995)
        total = float(np.sum(probs))
        if total <= 1e-12:
            return np.array([0.5, 0.5])
        return probs / total

    tau_tie = float(parameters['tau_tie'])
    if abs(tally) > tau_tie:
        beta_tally = float(parameters['beta_tally'])
        epsilon_tally = float(parameters['epsilon_tally'])
        if n >= int(parameters['n_low_conf']) and abs(tally) <= float(parameters['near_bound']):
            beta = float(parameters['beta_near'])
            eps = float(parameters['epsilon_near'])
        else:
            beta = beta_tally
            eps = epsilon_tally
        core = stable_softmax(np.array([tally, -tally]), beta)
        return lapse_mix(core, eps)

    flat_tol = float(parameters['flat_tol'])
    min_run_len = int(parameters['min_run_len'])
    runs = []
    run_start = 0
    for i in range(1, n):
        seg = validities[run_start:i + 1]
        if float(np.max(seg) - np.min(seg)) > flat_tol:
            if i - run_start >= min_run_len:
                runs.append((run_start, i))
            run_start = i
    if n - run_start >= min_run_len:
        runs.append((run_start, n))

    vmin = float(np.min(validities))
    vmax = float(np.max(validities))
    spread = max(vmax - vmin, 1e-9)

    def altitude_of(start, size):
        vals = validities[start:start + size]
        return float(np.clip((float(np.mean(vals)) - vmin) / spread, 0.0, 1.0))

    gain_min = float(parameters['gain_min'])
    gain_contrast = float(parameters['gain_contrast'])
    gain_flat = float(parameters['gain_flat'])
    contrast_ref = float(parameters['contrast_ref'])
    flat_ref = float(parameters['flat_ref'])
    contrast_power = float(parameters['contrast_power'])
    size_penalty = float(parameters['size_penalty'])
    size_penalty_high = float(parameters['size_penalty_high'])
    size_penalty_low = float(parameters['size_penalty_low'])
    high_altitude_threshold = float(parameters['high_altitude_threshold'])
    high_penalty_start = int(parameters['high_penalty_start'])
    moderate_gain_mult = float(parameters['moderate_gain_mult'])
    nonflat_gain_mult = float(parameters['nonflat_gain_mult'])
    low_gain_mult = float(parameters['low_gain_mult'])
    gain_floor = float(parameters['gain_floor'])
    gain_cap = float(parameters['gain_cap'])

    forced_limit_n = int(parameters['forced_n'])
    forced_loose_n = int(parameters['forced_loose_n'])
    forced_contrast_power = float(parameters['forced_contrast_power'])
    forced_late_flat_tol_short = float(parameters['forced_late_flat_tol_short'])
    forced_short_contrast = float(parameters['forced_short_contrast'])
    forced_short_gain_mult = float(parameters['forced_short_gain_mult'])
    forced_short_beta_mult = float(parameters['forced_short_beta_mult'])
    forced_short_eps = float(parameters['forced_short_eps'])
    forced_short_decisive_n = int(parameters['forced_short_decisive_n'])
    forced_short_beta_mult_strong = float(parameters['forced_short_beta_mult_strong'])
    forced_short_eps_strong = float(parameters['forced_short_eps_strong'])
    forced_large_eps = float(parameters['forced_large_eps'])
    forced_large_beta_mult = float(parameters['forced_large_beta_mult'])
    moderate_high_min_n = int(parameters['moderate_high_min_n'])
    moderate_high_n = int(parameters['moderate_high_n'])
    moderate_high_max_size = int(parameters['moderate_high_max_size'])
    moderate_high_gain_mult = float(parameters['moderate_high_gain_mult'])
    moderate_high_beta_mult = float(parameters['moderate_high_beta_mult'])
    moderate_high_eps = float(parameters['moderate_high_eps'])
    low_short_n = int(parameters['low_short_n'])
    low_short_max_size = int(parameters['low_short_max_size'])
    low_short_gain_mult = float(parameters['low_short_gain_mult'])
    low_short_beta_mult = float(parameters['low_short_beta_mult'])
    low_short_eps_reduce = float(parameters['low_short_eps_reduce'])
    size6_high_beta_mult = float(parameters['size6_high_beta_mult'])
    size6_high_lapse_add = float(parameters['size6_high_lapse_add'])
    moderate_large_gate_n = int(parameters['moderate_large_gate_n'])
    moderate_decisive_min_n = int(parameters['moderate_decisive_min_n'])
    moderate_decisive_max_n = int(parameters['moderate_decisive_max_n'])
    moderate_decisive_min_size = int(parameters['moderate_decisive_min_size'])
    moderate_eps_damp_max_n = int(parameters['moderate_eps_damp_max_n'])
    eps_terminal_moderate_lowalt = float(parameters['eps_terminal_moderate_lowalt'])
    long_high_beta_mult = float(parameters['long_high_beta_mult'])
    small_term_prefer_fallback_n = int(parameters['small_term_prefer_fallback_n'])
    small_term_max_size = int(parameters['small_term_max_size'])

    def make_candidate(start, size, kind, jump, contrast, block_vals, priority, flat):
        block_range = float(np.max(block_vals) - np.min(block_vals))
        altitude = altitude_of(start, size)
        flat_norm = float(np.clip(1.0 - block_range / flat_ref, 0.0, 1.0))
        if kind in ('terminal_strong', 'terminal_moderate', 'terminal_low', 'forced'):
            contrast_norm = float(np.clip(contrast / contrast_ref, 0.0, 1.0))
            contrast_pow = forced_contrast_power if kind == 'forced' else contrast_power
            gain = gain_min + gain_contrast * (contrast_norm ** contrast_pow) + gain_flat * flat_norm
        else:
            gain = gain_min + gain_flat * flat_norm

        if kind == 'terminal_moderate':
            if (n >= moderate_high_min_n and n <= moderate_high_n and
                    size <= moderate_high_max_size and altitude >= high_altitude_threshold):
                gain *= moderate_high_gain_mult
            else:
                gain *= moderate_gain_mult

        if kind == 'terminal_low':
            if n <= low_short_n and size <= low_short_max_size:
                gain *= low_short_gain_mult
            else:
                gain *= low_gain_mult

        if kind == 'forced' and not flat:
            if n <= forced_loose_n and contrast >= forced_short_contrast:
                gain *= forced_short_gain_mult
            else:
                gain *= nonflat_gain_mult

        if altitude >= high_altitude_threshold:
            penalty = size_penalty_high * max(0.0, float(size) - float(high_penalty_start) + 1.0)
        elif kind == 'terminal_low':
            penalty = size_penalty_low * max(0.0, float(size) - 3.0)
        else:
            penalty = size_penalty * max(0.0, float(size) - 3.0)
        if penalty > 0.0:
            gain /= (1.0 + penalty)

        return {
            'start': start,
            'size': size,
            'kind': kind,
            'jump': jump,
            'contrast': contrast,
            'block_range': block_range,
            'altitude': altitude,
            'priority': priority,
            'flat': flat,
            'gain': float(np.clip(gain, gain_floor, gain_cap))
        }

    min_term_len = int(parameters['min_term_len'])
    term_jump_hi = float(parameters['term_jump_hi'])
    term_jump_lo = float(parameters['term_jump_lo'])
    moderate_term_n = int(parameters['moderate_term_n'])
    term_low_max_size = int(parameters['term_low_max_size'])

    candidates = []
    for (rs, re) in runs:
        if re != n:
            continue
        size = re - rs
        if size < min_term_len:
            continue
        if rs == 0:
            continue
        jump = float(validities[rs] - validities[rs - 1])
        block_vals = validities[rs:re]
        contrast = float(abs(jump))
        if abs(jump) >= term_jump_hi:
            altitude = altitude_of(rs, size)
            if altitude >= high_altitude_threshold or size <= term_low_max_size:
                candidates.append(make_candidate(rs, size, 'terminal_strong', jump, contrast, block_vals, 4, True))
            else:
                candidates.append(make_candidate(rs, size, 'terminal_low', jump, contrast, block_vals, 2, True))
        elif n <= moderate_term_n and abs(jump) >= term_jump_lo:
            if n < moderate_large_gate_n or size <= 3:
                if (moderate_decisive_min_n <= n <= moderate_decisive_max_n and
                        size >= moderate_decisive_min_size and
                        altitude_of(rs, size) >= high_altitude_threshold):
                    cand = make_candidate(rs, size, 'terminal_strong', jump, contrast, block_vals, 4, True)
                    cand['moderate_decisive'] = True
                    candidates.append(cand)
                else:
                    candidates.append(make_candidate(rs, size, 'terminal_moderate', jump, contrast, block_vals, 3, True))

    if n <= forced_limit_n:
        forced_contrast_lo = float(parameters['forced_contrast_lo'])
        forced_prev_flat_tol = float(parameters['forced_prev_flat_tol'])
        forced_late_flat_tol = float(parameters['forced_late_flat_tol'])
        late_flat_tol_use = forced_late_flat_tol
        if n <= forced_loose_n:
            late_flat_tol_use = max(late_flat_tol_use, forced_late_flat_tol_short)

        for k in (3,):
            if n < 2 * k:
                continue
            prev = validities[n - 2 * k:n - k]
            late = validities[n - k:]
            contrast = float(np.mean(prev) - np.mean(late))
            prev_range = float(np.max(prev) - np.min(prev))
            late_range = float(np.max(late) - np.min(late))
            if contrast >= forced_contrast_lo and prev_range <= forced_prev_flat_tol and late_range <= late_flat_tol_use:
                flat = late_range <= flat_tol
                forced_priority = 5 if (n <= forced_short_decisive_n and flat and contrast >= forced_short_contrast) else 4
                candidates.append(make_candidate(n - k, k, 'forced', -contrast, contrast, late, forced_priority, flat))

        for k in (3,):
            if n < 2 * k:
                continue
            early = validities[:k]
            late = validities[-k:]
            contrast = float(np.mean(early) - np.mean(late))
            early_range = float(np.max(early) - np.min(early))
            late_range = float(np.max(late) - np.min(late))
            if contrast >= forced_contrast_lo and early_range <= forced_prev_flat_tol and late_range <= late_flat_tol_use:
                flat = late_range <= flat_tol
                forced_priority = 5 if (n <= forced_short_decisive_n and flat and contrast >= forced_short_contrast) else 4
                candidates.append(make_candidate(n - k, k, 'forced', -contrast, contrast, late, forced_priority, flat))

    fallback = None
    preceding_min_len = int(parameters['preceding_min_len'])
    preceding = []
    for (rs, re) in runs:
        if re < n and re - rs >= preceding_min_len:
            preceding.append((rs, re))
    if preceding:
        rs, re = min(preceding, key=lambda x: (x[0], -(x[1] - x[0])))
        block_vals = validities[rs:re]
        fallback = make_candidate(rs, re - rs, 'fallback', 0.0, 0.0, block_vals, 0, True)

    if not candidates and fallback is None:
        return np.array([0.5, 0.5])

    if candidates:
        c = max(candidates, key=lambda d: (d['priority'], d['gain'], d['contrast'], -d['size']))
        if (n >= small_term_prefer_fallback_n and fallback is not None and
                c['kind'] in ('terminal_strong', 'terminal_moderate', 'terminal_low') and
                c['size'] <= small_term_max_size and
                c['altitude'] < high_altitude_threshold):
            c = fallback
    else:
        c = fallback

    idx = np.arange(c['start'], c['start'] + c['size'], dtype=int)
    sub_tally = float(np.sum(diff[idx]))
    if abs(sub_tally) <= 1e-12:
        return np.array([0.5, 0.5])

    seg_beta = float(parameters['seg_beta'])
    beta_floor = float(parameters['beta_floor'])
    beta_cap = float(parameters['beta_cap'])
    beta_eff = float(np.clip(seg_beta * c['gain'], beta_floor, beta_cap))

    eps_size = float(parameters['eps_size'])
    eps_size_cap = int(parameters['eps_size_cap'])
    size_extra = min(max(0.0, float(c['size'] - 3)), float(eps_size_cap))

    forced_beta_mult = float(parameters['forced_beta_mult'])
    low_beta_mult = float(parameters['low_beta_mult'])
    eps_terminal_low = float(parameters['eps_terminal_low'])
    fallback_large_min_n = int(parameters['fallback_large_min_n'])
    fallback_large_beta_mult = float(parameters['fallback_large_beta_mult'])
    fallback_large_eps = float(parameters['fallback_large_eps'])
    moderate_decisive_beta_mult = float(parameters['moderate_decisive_beta_mult'])
    moderate_decisive_eps = float(parameters['moderate_decisive_eps'])

    short_forced = (c['kind'] == 'forced' and n <= forced_loose_n and
                    c['size'] == 3 and c['contrast'] >= forced_short_contrast)
    strong_short_forced = (short_forced and c['flat'] and n <= forced_short_decisive_n)

    if c['kind'] == 'fallback':
        fallback_beta_mult = float(parameters['fallback_beta_mult'])
        beta_eff *= fallback_beta_mult
        eps = float(parameters['eps_fallback'])
        if n >= fallback_large_min_n and c['altitude'] < high_altitude_threshold:
            beta_eff *= fallback_large_beta_mult
            eps = fallback_large_eps
    elif c['kind'] == 'forced':
        if strong_short_forced:
            beta_eff *= forced_short_beta_mult_strong
            eps = forced_short_eps_strong
        elif short_forced:
            beta_eff *= forced_short_beta_mult
            eps = forced_short_eps
        else:
            beta_eff *= forced_beta_mult
            eps = float(parameters['eps_forced'])
            if not c['flat']:
                eps += float(parameters['nonflat_eps_add'])
            if n >= 12:
                beta_eff *= forced_large_beta_mult
                eps = forced_large_eps
    elif c['kind'] == 'terminal_moderate':
        if (n >= moderate_high_min_n and n <= moderate_high_n and
                c['size'] <= moderate_high_max_size and c['altitude'] >= high_altitude_threshold):
            beta_eff *= moderate_high_beta_mult
            eps = moderate_high_eps
        elif n <= moderate_eps_damp_max_n and c['altitude'] < high_altitude_threshold:
            eps = eps_terminal_moderate_lowalt
        else:
            eps = float(parameters['eps_terminal_moderate']) + eps_size * size_extra
    elif c['kind'] == 'terminal_low':
        if n <= low_short_n and c['size'] <= low_short_max_size:
            beta_eff *= low_short_beta_mult
            eps = max(0.0, eps_terminal_low - low_short_eps_reduce) + eps_size * size_extra
        else:
            beta_eff *= low_beta_mult
            eps = eps_terminal_low + eps_size * size_extra
    elif c['kind'] == 'terminal_strong':
        if c.get('moderate_decisive'):
            beta_eff *= moderate_decisive_beta_mult
            eps = moderate_decisive_eps
        else:
            eps = float(parameters['eps_terminal_strong']) + eps_size * size_extra
            if c['altitude'] >= high_altitude_threshold:
                eps += float(parameters['eps_high_altitude_add'])
                if c['size'] >= int(parameters['long_high_min_size']):
                    eps += float(parameters['long_high_eps_add'])
                    beta_eff *= long_high_beta_mult
                if c['size'] == 6:
                    beta_eff *= size6_high_beta_mult
                    eps += size6_high_lapse_add

    eps = float(np.clip(eps, 0.0, 0.97))
    core = stable_softmax(np.array([sub_tally, -sub_tally]), beta_eff)
    return lapse_mix(core, eps)


`policy(probs) -> int`:
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=np.float64)
    p = np.clip(p, 0.0, None)
    total = float(p.sum())
    if total <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / total
    return int(np.random.choice(len(p), p=p))


## THEORY 2 — pi_10
People make binary-feature choices by a primary unweighted signed tally. When the tally is clear, choice follows the tally through a softmax with a small lapse. When the tally is tied or near-tied, people parse the advertised validity display into a single contiguous terminal chunk only when that chunk is coherent, i.e. its validity profile is flat and bounded by a clear validity discontinuity. Inside an opened terminal chunk the choice is based on an unweighted or validity-ordered sub-tally, never on positive exponential recency. When no coherent terminal chunk opens on a short display, people pool the earliest/largest coherent preceding block and choose by its sub-tally, producing directional anti-recency on late-block metrics. A targeted forced late-pool route is retained for very short displays in which an early homogeneous high-validity block is followed by a lower homogeneous late block.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('Expected a (2, n_features) stimulus.')

    validities = np.asarray(parameters['validities'], dtype=float)
    n_features = stim.shape[1]
    if validities.shape[0] != n_features:
        raise ValueError('validities length mismatch.')

    a = stim[0]
    b = stim[1]
    diff = a - b
    tally = float(np.sum(diff))

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        denom = float(np.sum(e))
        if denom <= 1e-12:
            return np.ones_like(scores, dtype=float) / float(len(scores))
        return e / denom

    def lapse_mix(core, eps):
        probs = (1.0 - eps) * core + eps * np.array([0.5, 0.5])
        probs = np.clip(probs, 0.005, 0.995)
        total = float(np.sum(probs))
        if total <= 1e-12:
            return np.array([0.5, 0.5])
        return probs / total

    vmin = float(np.min(validities))
    vmax = float(np.max(validities))
    spread = max(vmax - vmin, 1e-9)

    def find_block():
        candidates = []
        gap_hi = float(parameters['gap_hi'])
        gap_lo = float(parameters['gap_lo'])
        gap_pos_max = float(parameters['gap_pos_max'])
        drop_lo = float(parameters['drop_lo'])
        drop_hi = float(parameters['drop_hi'])
        flat_tol = float(parameters['flat_tol'])
        block_max_large = int(parameters['block_max_large'])
        block_max_small = int(parameters['block_max_small'])
        moderate_allowed = n_features <= int(parameters['moderate_max_features'])

        for size in range(2, min(block_max_large, n_features - 1) + 1):
            start = n_features - size
            if start < 1:
                continue
            jump = float(validities[start] - validities[start - 1])
            block_vals = validities[start:]
            block_range = float(np.max(block_vals) - np.min(block_vals))
            if block_range > flat_tol:
                continue

            kind = None
            direction = 0
            if moderate_allowed and size <= block_max_small:
                if gap_lo <= jump <= gap_pos_max:
                    kind = 'positive_end'
                    direction = 1
                elif -drop_hi <= jump <= -drop_lo:
                    kind = 'negative_end'
                    direction = -1
            if abs(jump) >= gap_hi:
                kind = 'large_jump'
                direction = 1 if jump > 0.0 else -1

            if kind is not None:
                candidates.append({
                    'start': start,
                    'size': size,
                    'jump': jump,
                    'contrast': abs(jump),
                    'block_vals': block_vals,
                    'block_range': block_range,
                    'direction': direction,
                    'kind': kind,
                    'gain_override': None
                })

        if n_features <= int(parameters['short_max_features']):
            cum_lo = float(parameters['cum_lo'])
            cum_hi = float(parameters['cum_hi'])
            cum_late_flat = float(parameters['cum_late_flat_tol'])
            cum_prev_flat = float(parameters['cum_prev_flat_tol'])
            for k in (3, 2):
                if n_features < 2 * k:
                    continue
                prev = validities[n_features - 2 * k:n_features - k]
                late = validities[n_features - k:]
                late_range = float(np.max(late) - np.min(late))
                prev_range = float(np.max(prev) - np.min(prev))
                contrast = float(np.mean(prev) - np.mean(late))
                if (cum_lo <= contrast <= cum_hi and
                        late_range <= cum_late_flat and
                        prev_range <= cum_prev_flat):
                    candidates.append({
                        'start': n_features - k,
                        'size': k,
                        'jump': contrast,
                        'contrast': contrast,
                        'block_vals': late,
                        'block_range': late_range,
                        'direction': -1,
                        'kind': 'cumulative_late',
                        'gain_override': None
                    })

        if n_features <= int(parameters['forced_max_features']):
            forced_lo = float(parameters['forced_contrast_lo'])
            forced_hi = float(parameters['forced_contrast_hi'])
            forced_late_flat = float(parameters['forced_late_flat_tol'])
            forced_prev_flat = float(parameters['forced_prev_flat_tol'])
            forced_alt = float(parameters['forced_altitude_lo'])
            forced_gain = float(parameters['forced_gain'])
            k = 3
            if n_features >= 2 * k:
                prev = validities[n_features - 2 * k:n_features - k]
                late = validities[n_features - k:]
                contrast = float(np.mean(prev) - np.mean(late))
                late_range = float(np.max(late) - np.min(late))
                prev_range = float(np.max(prev) - np.min(prev))
                if (forced_lo <= contrast <= forced_hi and
                        late_range <= forced_late_flat and
                        prev_range <= forced_prev_flat and
                        float(vmax - np.mean(late)) >= forced_alt):
                    candidates.append({
                        'start': n_features - k,
                        'size': k,
                        'jump': contrast,
                        'contrast': contrast,
                        'block_vals': late,
                        'block_range': late_range,
                        'direction': -1,
                        'kind': 'forced_late_pool',
                        'gain_override': forced_gain
                    })

        if not candidates and n_features <= int(parameters['short_max_features']):
            short_drop_min = float(parameters['short_drop_min'])
            jumps = np.abs(np.diff(validities))
            order = np.argsort(-jumps, kind='stable')
            for jpos in order:
                jpos = int(jpos)
                size = n_features - (jpos + 1)
                if size < 2 or size > block_max_large:
                    continue
                jump = float(validities[jpos + 1] - validities[jpos])
                if abs(jump) < short_drop_min:
                    continue
                late_vals = validities[jpos + 1:]
                block_range = float(np.max(late_vals) - np.min(late_vals))
                if block_range > flat_tol:
                    continue
                candidates.append({
                    'start': jpos + 1,
                    'size': size,
                    'jump': jump,
                    'contrast': abs(jump),
                    'block_vals': late_vals,
                    'block_range': block_range,
                    'direction': 1 if jump > 0.0 else -1,
                    'kind': 'largest_drop_short',
                    'gain_override': None
                })
                break

        if not candidates:
            return None

        strength_min = float(parameters['strength_min'])
        strength_high_extreme = float(parameters['strength_high_extreme'])
        strength_contrast = float(parameters['strength_contrast'])
        strength_flat = float(parameters['strength_flat'])
        contrast_ref = float(parameters['contrast_ref'])
        contrast_power = float(parameters['contrast_power'])
        altitude_power = float(parameters['altitude_power'])
        flat_ref = float(parameters['flat_ref'])
        size_penalty = float(parameters['size_penalty'])
        gain_floor = float(parameters['gain_floor'])
        gain_cap = float(parameters['gain_cap'])

        for c in candidates:
            if c.get('gain_override') is not None:
                c['gain'] = float(c['gain_override'])
                continue

            flat_norm = float(np.clip(1.0 - c['block_range'] / flat_ref, 0.0, 1.0))
            if c['direction'] > 0:
                altitude = float(np.clip((float(np.mean(c['block_vals'])) - vmin) / spread, 0.0, 1.0))
                contrast_term = strength_high_extreme * (altitude ** altitude_power)
            else:
                base = float(np.clip(c['contrast'] / contrast_ref, 0.0, 1.0))
                contrast_term = strength_contrast * (base ** contrast_power)
            gain = strength_min + contrast_term + strength_flat * flat_norm
            if c['size'] > 3:
                gain = gain / (1.0 + size_penalty * (c['size'] - 3))
            c['gain'] = float(np.clip(gain, gain_floor, gain_cap))

        return max(candidates, key=lambda c: (c['kind'] == 'forced_late_pool', c['gain'], c['contrast'], -c['size']))

    def find_fallback_pool():
        pool_flat_tol = float(parameters['pool_flat_tol'])
        pool_min_size = int(parameters['pool_min_size'])
        runs = []
        start = 0
        for i in range(1, n_features + 1):
            if i == n_features:
                length = i - start
                if length >= pool_min_size:
                    runs.append((start, i))
                break
            if max(validities[start:i + 1]) - min(validities[start:i + 1]) > pool_flat_tol:
                length = i - start
                if length >= pool_min_size:
                    runs.append((start, i))
                start = i

        preceding = [r for r in runs if r[1] < n_features]
        if not preceding:
            return None
        rank = str(parameters['pool_rank'])
        if rank == 'earliest':
            return min(preceding, key=lambda r: (r[0], -(r[1] - r[0])))
        return max(preceding, key=lambda r: (r[1] - r[0], -r[0]))

    tau_tie = float(parameters['tau_tie'])

    if abs(tally) <= tau_tie:
        block = find_block()
        if block is not None and block['size'] >= 2:
            idx = np.arange(block['start'], block['start'] + block['size'], dtype=int)
            size = int(block['size'])
            vals = validities[idx]
            if float(np.max(vals) - np.min(vals)) > 1e-9:
                val_floor = float(parameters['val_weight_floor'])
                val_power = float(parameters['val_weight_power'])
                w = np.asarray((vals - vmin + val_floor) ** val_power, dtype=float)
            else:
                w = np.ones(size, dtype=float)
            denom = float(np.sum(w))
            if denom <= 1e-12:
                w = np.ones(size, dtype=float)
            else:
                w = w / denom * float(size)

            sub_tally = float(np.dot(w, diff[idx]))
            beta_sub = float(parameters['beta_sub'])
            beta_eff = float(np.clip(beta_sub * block['gain'], 0.05, 2.0))

            is_forced = block.get('kind') == 'forced_late_pool'
            if is_forced:
                beta_eff = float(np.clip(beta_sub * block['gain'] * float(parameters['forced_beta_mult']), 0.05, 2.0))
                eps_eff = float(np.clip(float(parameters['forced_eps']), 0.0, 0.90))
            else:
                eps_sub = float(parameters['epsilon_sub'])
                eps_sub_size = float(parameters['epsilon_sub_size'])
                eps_eff = float(np.clip(eps_sub + eps_sub_size * max(0.0, float(size - 3)), 0.0, 0.90))

            if abs(sub_tally) > 1e-12:
                core = stable_softmax(np.array([sub_tally, -sub_tally]), beta_eff)
                return lapse_mix(core, eps_eff)
            return np.array([0.5, 0.5])

        fallback_min = int(parameters['fallback_min_features'])
        fallback_max = int(parameters['fallback_max_features'])
        if fallback_min <= n_features <= fallback_max:
            pool = find_fallback_pool()
            if pool is not None:
                idx = np.arange(pool[0], pool[1], dtype=int)
                sub_tally = float(np.sum(diff[idx]))
                if abs(sub_tally) > 1e-12:
                    core = stable_softmax(np.array([sub_tally, -sub_tally]), float(parameters['pool_beta']))
                    return lapse_mix(core, float(parameters['pool_eps']))
                return np.array([0.5, 0.5])

        return np.array([0.5, 0.5])

    beta_small = float(parameters['beta_tally_small'])
    beta_large = float(parameters['beta_tally_large'])
    eps_small = float(parameters['epsilon_tally_small'])
    eps_large = float(parameters['epsilon_tally_large'])
    frac = float(np.clip((n_features - 8.0) / 7.0, 0.0, 1.0))
    beta_tally = beta_small + frac * (beta_large - beta_small)
    epsilon_tally = eps_small + frac * (eps_large - eps_small)

    low_conf = (n_features >= int(parameters['n_low_conf'])) and (abs(tally) <= float(parameters['near_bound']))
    if low_conf:
        beta = float(parameters['beta_near'])
        eps = float(parameters['epsilon_near'])
    else:
        beta = beta_tally
        eps = epsilon_tally

    core = stable_softmax(np.array([tally, -tally]), beta)
    return lapse_mix(core, eps)


`policy(probs) -> int`:
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=np.float64)
    p = np.clip(p, 0.0, None)
    total = float(p.sum())
    if total <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / total
    return int(np.random.choice(len(p), p=p))


## EXPERIMENT 1 (proposed by pi_11)

### DESIGN
**Validities (n_features=15):** [0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.95, 0.95, 0.95]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]
  trial 2: A=[1, 1, 1, 1, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  trial 3: A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1]
  trial 4: A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 1]
  trial 7: A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  trial 8: A=[0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1]

**Rationale:** This design uses 15 features. The first 12 experts all have validity 0.50, and the last three have validity 0.95, creating one large upward validity jump of 0.45 into a terminal triplet. Every unique pair has a total tally d = sum(A - B) of either +1 or -1. For the advocated theory, |d| is below tau_tie = 2.5, so the model enters its near-tie segmentation route and selects the terminal triplet because it is a size-3 block opened by a large validity discontinuity. Choice is then driven only by the terminal sub-tally t = sum of the last three differences. For the competing theory, |d| = 1 is above its tau_tie = 0.5, so it never opens a terminal block. Because n_features = 15 and |d| = 1 is within its low-confidence near-tally band, the competing model uses its weak near-tally route with beta_near around 0.18 to 0.38 and epsilon_near around 0.75 to 0.95, producing p(A) close to 0.5 for every +1 pair and every -1 pair regardless of t. The eight unique pairs hold d constant at +1 or -1 while t takes the values -3, -1, +1, +3. The advocated theory therefore predicts a strongly t-ordered psychometric curve, from about 0.09 for t = -3 up to about 0.89 for t = +3, with sign reversals relative to the total tally on the t-opposing trials. The competing theory predicts a nearly flat line at chance, with only a tiny d shift of about 0.01 to 0.03 away from 0.5. This gives a quantitative dissociation: a four-level t-ordered curve versus a flat near-chance line within each total-tally block. The 8 unique pairs are repeated 12 times for 96 trials.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric isolates the terminal-triplet contrast predicted by the advocated model. It computes the signed difference t between A and B on the last three high-validity features, then compares the proportion of A choices for trials with terminal sub-tally t = +3 versus t = -3. The advocated model enters its near-tie segmentation route because the full tally is only +1 or -1 and selects the terminal triplet, producing a strong gradient with p(A) around 0.10 for t = -3 and around 0.90 for t = +3, giving a contrast near 0.80. The competing model never opens the terminal block because its tie threshold is smaller, and its low-confidence near-tally route keeps p(A) near 0.50 regardless of t. The total-tally effect also cancels because each t level contains one pair with total tally +1 and one with total tally -1. Using proportions over many repeated trials keeps between-subject variance small relative to the large mean gap.

Source:
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    if len(data) == 0:
        return 0.0
    A = np.vstack(data['option_a_ratings'].tolist())
    B = np.vstack(data['option_b_ratings'].tolist())
    t = (A[:, -3:] - B[:, -3:]).sum(axis=1)
    chose_a = (np.asarray(data['response']) == 0).astype(float)
    high = t == 3
    low = t == -3
    if not np.any(high) or not np.any(low):
        return 0.0
    return float(np.mean(chose_a[high]) - np.mean(chose_a[low]))


### RESULTS
- Predicted under pi_11 (simulated): 0.8175 (var=0.0092)
- Predicted under pi_10 (simulated): 0.0017 (var=0.0187)
- Observed on real data: 0.0433 (var=0.0113)

## EXPERIMENT 2 (proposed by pi_10)

### DESIGN
**Validities (n_features=10):** [0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.95, 0.87, 0.86, 0.85]

**Trial pairs (n=12):**
  trial 1: A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 1, 1]
  trial 2: A=[1, 0, 1, 1, 1, 1, 0, 0, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  trial 3: A=[1, 1, 1, 0, 1, 1, 1, 0, 1, 0]  B=[1, 1, 0, 1, 1, 1, 0, 1, 0, 1]
  trial 4: A=[1, 1, 1, 1, 1, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 1, 1, 0, 1, 0]
  trial 5: A=[1, 1, 0, 1, 1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1, 0, 0, 1, 1]
  trial 6: A=[1, 0, 1, 0, 1, 1, 0, 0, 1, 1]  B=[0, 1, 0, 1, 1, 1, 1, 1, 0, 0]
  trial 7: A=[1, 1, 1, 1, 0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 1, 1, 0, 1, 0, 1]
  trial 8: A=[0, 1, 1, 1, 1, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 1, 1, 1, 0, 1, 0]
  trial 9: A=[1, 1, 0, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1, 0, 0, 1, 1]
  trial 10: A=[1, 1, 1, 1, 0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0, 1, 1, 0, 0]
  trial 11: A=[1, 1, 1, 0, 1, 1, 1, 0, 1, 0]  B=[1, 0, 1, 1, 1, 1, 0, 1, 0, 1]
  trial 12: A=[1, 1, 1, 0, 1, 0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1, 1, 0, 1, 0]

**Rationale:** This design isolates the key difference in how the two theories resolve an opened terminal chunk: the advocated theory uses validity-ordered weights inside a nonflat terminal block, while the competing theory uses equal weights inside the recognized segment. The validity vector has six 0.50 experts followed by terminal experts [0.95, 0.87, 0.86, 0.85], creating a clear 0.45 upward discontinuity into a flat terminal block with range 0.10. Every unique pair is an exact full-tally tie (sum A-B = 0), so both theories enter their tied/segmentation route and both select this final four-feature terminal chunk through the large-jump route. Inside the terminal chunk, the unweighted difference sum is exactly zero on every trial (two features favor A and two favor B), so the competing equal-weight segment predicts p(A) = 0.50 for all 12 unique pairs. The advocated validity-ordered sub-tally is nonzero because feature 6 (validity 0.95) and, to a lesser degree, feature 7 (0.87) receive more weight than features 8-9 (0.86, 0.85). Trials 1, 5, 9 use terminal pattern +,+,-,- and trials 3, 7, 11 use terminal pattern +,-,+,-, yielding positive weighted sub-tallies; trials 2, 6, 10 and 4, 8, 12 are their exact A/B mirrors, yielding negative weighted sub-tallies. The +,+,-,- patterns give a larger weighted sub-tally than the +,-,+,- patterns for the advocated theory, producing a graded positive/negative psychometric dissociation against the competing theory's flat 0.50 line. The first six filler features also have zero difference sum on every trial, so they vary trial identity without changing the primary tally. Twelve unique pairs repeated eight times gives roughly 96 trials per subject.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
Every unique pair has a zero full tally and a zero unweighted terminal tally, so the competing equal-weight segment theory predicts a B-choice probability of 0.5 on every trial regardless of which terminal features favor B. The advocated validity-ordered theory instead weights terminal features 6 through 9 by their validities 0.95, 0.87, 0.86, and 0.85, producing a signed terminal score that shifts choices toward the option favored by the higher-validity experts. This metric computes that terminal validity-weighted A minus B score for each trial, partitions trials by its sign, and returns the weighted B-choice proportion on negative-score trials minus the weighted B-choice proportion on positive-score trials. The competing theory gives an expected value near 0; the advocated theory gives a positive value. The contrast uses all 96 trials and is tight per subject because positive and negative terminal configurations are equally frequent and mirror each other.

Source:
def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.95, 0.87, 0.86, 0.85], dtype=float)
    term_vals = validities[6:10]
    a_rows = [np.asarray(x, dtype=float) for x in data['option_a_ratings'].tolist()]
    b_rows = [np.asarray(x, dtype=float) for x in data['option_b_ratings'].tolist()]
    a = np.vstack(a_rows)
    b = np.vstack(b_rows)
    y = data['response'].to_numpy(dtype=float)
    diff = a - b
    terminal_diff = diff[:, 6:10]
    score = terminal_diff @ term_vals
    pos = score > 1e-12
    neg = score < -1e-12
    if np.count_nonzero(pos) == 0 or np.count_nonzero(neg) == 0:
        return 0.0
    weights = np.abs(score)
    p_neg = float(np.sum(weights[neg] * y[neg]) / np.sum(weights[neg]))
    p_pos = float(np.sum(weights[pos] * y[pos]) / np.sum(weights[pos]))
    return float(p_neg - p_pos)

### RESULTS
- Predicted under pi_11 (simulated): -0.0054 (var=0.0104)
- Predicted under pi_10 (simulated): 0.0783 (var=0.0088)
- Observed on real data: 0.0411 (var=0.0094)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.92, 0.84, 0.76, 0.68, 0.6, 0.5])
    cue_order = np.argsort(-validities, kind='stable')
    A = np.array([np.asarray(row, dtype=float) for row in data['option_a_ratings']])
    B = np.array([np.asarray(row, dtype=float) for row in data['option_b_ratings']])
    resp_is_a = (data['response'].to_numpy(dtype=float) == 0.0).astype(float)

    winner = np.full(A.shape[0], -1, dtype=int)
    unresolved = np.ones(A.shape[0], dtype=bool)
    for j in cue_order:
        diff = A[:, j] - B[:, j]
        first = unresolved & (diff != 0)
        winner[first] = np.where(diff[first] > 0, 0, 1)
        unresolved[first] = False

    tally = (A > B).sum(axis=1) - (B > A).sum(axis=1)
    side = np.where(winner == 0, 1.0, np.where(winner == 1, -1.0, 0.0))
    signed_weight = side * (np.abs(tally) + 1.0)

    numerator = float(np.sum(signed_weight * resp_is_a))
    denom = float(np.sum(signed_weight[signed_weight > 0]))
    if denom == 0.0:
        return 0.0
    return numerator / denom

```

**Observed (real) value:** -0.6137 (var=0.0420)
**Predicted under pi_11:** -0.6665 (var=0.0256)
**Predicted under pi_10:** -0.7177 (var=0.0022)

### Experiment 4
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 0, 0, 0]  B=[0, 1, 1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    resp = data['response'].astype(int).tolist()

    # Highest validity is at display index 4: [0.57, 0.7, 0.5, 0.77, 0.92, 0.84, 0.63, 0.52]
    top_idx = 4

    xs = []
    ys = []

    for a, b, r in zip(a_col, b_col, resp):
        if a[top_idx] == b[top_idx]:
            continue

        top_is_a = a[top_idx] > b[top_idx]

        a_wins = 0
        b_wins = 0
        for fa, fb in zip(a, b):
            if fa > fb:
                a_wins += 1
            elif fb > fa:
                b_wins += 1

        d = a_wins - b_wins
        if d == 0:
            continue

        # Signed tally advantage for the option favored by the top cue.
        signed_tally_for_top = d if top_is_a else -d

        # 1 if the subject chose the option favored by the top cue, else 0.
        top_chosen = 1.0 if ((top_is_a and r == 0) or ((not top_is_a) and r == 1)) else 0.0

        xs.append(float(signed_tally_for_top))
        ys.append(top_chosen)

    if len(xs) < 2:
        return 0.0

    x = np.asarray(xs, dtype=float)
    y = np.asarray(ys, dtype=float)

    xm = x.mean()
    sxx = float(np.sum((x - xm) ** 2))
    if sxx <= 0:
        return 0.0

    slope = float(np.sum((x - xm) * (y - y.mean())) / sxx)
    return slope
```

**Observed (real) value:** 0.0659 (var=0.0002)
**Predicted under pi_11:** 0.0753 (var=0.0000)
**Predicted under pi_10:** 0.0860 (var=0.0000)

### Experiment 5
**Design**
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.5, 0.5, 0.5, 0.5, 0.5, 0.5,
                           1.0, 1.0, 1.0, 1.0, 1.0, 1.0], dtype=float)
    centered = validities - validities.mean()

    cap = 3.0
    subj_vals = []

    for _, sub in data.groupby('subject_id'):
        a = np.asarray(sub['option_a_ratings'].tolist(), dtype=float)
        b = np.asarray(sub['option_b_ratings'].tolist(), dtype=float)
        diff = a - b
        tally = diff.sum(axis=1)
        s = diff @ centered

        mask = np.abs(tally) < 1e-9
        if int(mask.sum()) < 4:
            continue

        s0 = s[mask]
        resp = sub['response'].to_numpy(dtype=float)
        y = (resp[mask] == 0.0).astype(float)

        score = float(np.sum(s0 * (y - 0.5)))
        null_sd = float(np.sqrt(0.25 * np.sum(s0 * s0)))
        if null_sd <= 1e-12:
            continue

        z = score / null_sd
        subj_vals.append(float(min(abs(z), cap)))

    if not subj_vals:
        return 0.0
    return float(np.mean(subj_vals))

```

**Observed (real) value:** 2.6289 (var=0.2854)
**Predicted under pi_11:** 2.5200 (var=0.4284)
**Predicted under pi_10:** 2.9956 (var=0.0010)

### Experiment 6
**Design**
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.5, 0.5, 0.5, 0.6, 0.7, 0.8, 0.9, 1.0, 1.0, 1.0])
    centered = validities - validities.mean()

    def one_subject_stat(sub):
        A = np.array(sub['option_a_ratings'].tolist(), dtype=float)
        B = np.array(sub['option_b_ratings'].tolist(), dtype=float)
        y = (sub['response'].to_numpy() == 0).astype(float)
        diff = A - B
        tie_trial_mask = np.isclose(np.sum(diff, axis=1), 0.0)
        s = diff.dot(centered)
        score = np.sum(s[tie_trial_mask] * y[tie_trial_mask])
        null_var = 0.25 * np.sum(s[tie_trial_mask] ** 2)
        if null_var <= 0.0:
            return 0.0
        z = score / np.sqrt(null_var)
        return float(np.abs(z) - 0.7978845608028654)

    if data['subject_id'].nunique() == 1:
        return one_subject_stat(data)

    values = [one_subject_stat(sub) for _, sub in data.groupby('subject_id', sort=False)]
    if not values:
        return 0.0
    return float(np.mean(values))

```

**Observed (real) value:** 4.2015 (var=2.0036)
**Predicted under pi_11:** 5.2765 (var=0.0973)
**Predicted under pi_10:** 4.3750 (var=0.4914)

### Experiment 7
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    a = np.asarray(data['option_a_ratings'].tolist(), dtype=float)
    b = np.asarray(data['option_b_ratings'].tolist(), dtype=float)
    diff = a - b
    total_tally = diff.sum(axis=1)
    high_tally = diff[:, 8:].sum(axis=1)
    chose_a = (data['response'].to_numpy() == 0).astype(float)
    subject = data['subject_id'].to_numpy()

    per_subject = []
    for sid in np.unique(subject):
        idx = subject == sid
        tie = total_tally[idx] == 0.0
        high_pos = high_tally[idx] > 0
        high_neg = high_tally[idx] < 0
        pos_trials = tie & high_pos
        neg_trials = tie & high_neg
        if pos_trials.sum() > 0 and neg_trials.sum() > 0:
            diff_rate = float(chose_a[idx][pos_trials].mean() - chose_a[idx][neg_trials].mean())
            per_subject.append(diff_rate)

    if not per_subject:
        return float('nan')

    return float(np.mean(per_subject))
```

**Observed (real) value:** -0.0467 (var=0.0156)
**Predicted under pi_11:** 0.0483 (var=0.0589)
**Predicted under pi_10:** 0.0233 (var=0.0370)

### Experiment 8
**Design**
  A=[1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 1, 0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1, 1, 0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0, 1, 1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0, 0, 1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    if data.empty:
        return 0.0

    validities = np.array([0.5, 0.5, 0.5, 0.5, 0.6, 0.7, 0.8, 0.9, 1.0, 1.0, 1.0, 1.0], dtype=float)
    weights = (validities - 0.5) ** 6.0

    a = np.array(data['option_a_ratings'].tolist(), dtype=float)
    b = np.array(data['option_b_ratings'].tolist(), dtype=float)
    resp = data['response'].to_numpy(dtype=float)

    diff = a - b
    tally = (a > b).sum(axis=1) - (b > a).sum(axis=1)
    tie_mask = tally == 0

    if not np.any(tie_mask):
        return 0.0

    v = diff[tie_mask] @ weights
    y = resp[tie_mask]
    signed_accuracy = np.sign(v) * (1.0 - 2.0 * y)
    abs_v = np.abs(v)
    total_weight = float(abs_v.sum())

    if total_weight <= 0.0:
        return 0.0

    return float(np.sum(abs_v * signed_accuracy) / total_weight)

```

**Observed (real) value:** 0.0204 (var=0.0176)
**Predicted under pi_11:** -0.0085 (var=0.0349)
**Predicted under pi_10:** -0.0007 (var=0.0362)

### Experiment 9
**Design**
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    df = data.copy()
    df["_order"] = df.groupby("subject_id", sort=False).cumcount()
    df = df[df["_order"] >= 12]
    if df.empty:
        return 0.0

    a = np.asarray(df["option_a_ratings"].tolist(), dtype=float)
    b = np.asarray(df["option_b_ratings"].tolist(), dtype=float)
    d = (a - b).sum(axis=1)
    resp = df["response"].to_numpy().astype(int)

    v = np.array([0.5, 0.6, 0.7, 0.8, 0.9, 1.0, 0.85, 0.75, 0.65, 0.95, 0.99])
    w = v - 0.5

    ties = np.abs(d) < 0.5
    non_ties = ~ties

    if ties.any():
        tie_scores = np.dot(a[ties] - b[ties], w)
        validity_side = np.where(tie_scores > 0, 0, 1)
        tie_rate = float(np.mean(resp[ties] == validity_side))
    else:
        tie_rate = 0.5

    if non_ties.any():
        tally_side = np.where(d[non_ties] > 0, 0, 1)
        non_tie_rate = float(np.mean(resp[non_ties] == tally_side))
    else:
        non_tie_rate = 0.5

    return tie_rate - non_tie_rate

```

**Observed (real) value:** -0.5522 (var=0.0900)
**Predicted under pi_11:** -0.5767 (var=0.0105)
**Predicted under pi_10:** -0.5471 (var=0.0474)

### Experiment 10
**Design**
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    subjects = list(data['subject_id'].unique())
    z_scores = []
    for sid in subjects:
        sub = data[data['subject_id'] == sid]
        d_vals = []
        s_vals = []
        y_vals = []
        for _, row in sub.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            n = a.size
            if n < 2:
                continue
            half = n // 2
            diff = a - b
            high = float(np.sum(diff[:half]))
            low = float(np.sum(diff[half:]))
            d = high + low
            s = 0.25 * (high - low)
            y = 1.0 - float(row['response'])
            d_vals.append(d)
            s_vals.append(s)
            y_vals.append(y)
        if len(y_vals) < 10:
            continue
        X = np.column_stack([
            np.ones(len(y_vals)),
            np.asarray(d_vals, dtype=float),
            np.asarray(s_vals, dtype=float)
        ])
        y = np.asarray(y_vals, dtype=float)
        beta = np.linalg.lstsq(X, y, rcond=None)[0]
        beta = np.asarray(beta, dtype=float).ravel()
        p_hat = X @ beta
        p_hat = np.clip(p_hat, 0.005, 0.995)
        resid = y - p_hat
        XtX = X.T @ X
        try:
            bread = np.linalg.inv(XtX)
        except np.linalg.LinAlgError:
            bread = np.linalg.pinv(XtX)
        meat = (X * (resid ** 2)[:, None]).T @ X
        cov = bread @ meat @ bread
        se_d = float(np.sqrt(max(cov[1, 1], 1e-12)))
        z_d = float(beta[1]) / se_d if se_d > 0 else 0.0
        z_scores.append(z_d)
    if len(z_scores) == 0:
        return 0.0
    if len(subjects) > 1:
        return float(np.var(np.asarray(z_scores, dtype=float), ddof=0))
    return float(z_scores[0])
```

**Observed (real) value:** 0.9276 (var=0.9276)
**Predicted under pi_11:** 1.0411 (var=1.0411)
**Predicted under pi_10:** 1.3220 (var=1.3220)

### Experiment 11
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    if len(data) == 0:
        return 0.0
    a = np.asarray(list(data['option_a_ratings']), dtype=float)
    b = np.asarray(list(data['option_b_ratings']), dtype=float)
    tally = np.sum(a - b, axis=1)
    resp = data['response'].to_numpy(dtype=float)
    pos_mask = tally > 0.0
    neg_mask = tally < 0.0
    pos_mean = float(np.mean(resp[pos_mask])) if np.any(pos_mask) else 0.5
    neg_mean = float(np.mean(resp[neg_mask])) if np.any(neg_mask) else 0.5
    return neg_mean - pos_mean

```

**Observed (real) value:** 0.0300 (var=0.0026)
**Predicted under pi_11:** 0.0175 (var=0.0060)
**Predicted under pi_10:** 0.0358 (var=0.0135)

### Experiment 12
**Design**
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data):
    # Top three features are the three perfectly valid experts in this design.
    a_top = np.array([float(r[0] + r[1] + r[2]) for r in data['option_a_ratings']])
    b_top = np.array([float(r[0] + r[1] + r[2]) for r in data['option_b_ratings']])
    top_tally = a_top - b_top

    chose_a = 1.0 - np.asarray(data['response'], dtype=float)

    mask_pos3 = top_tally == 3
    mask_neg3 = top_tally == -3

    if mask_pos3.sum() == 0 or mask_neg3.sum() == 0:
        return 0.0

    p_a_given_top_plus3 = chose_a[mask_pos3].mean()
    p_a_given_top_minus3 = chose_a[mask_neg3].mean()
    return float(p_a_given_top_plus3 - p_a_given_top_minus3)

```

**Observed (real) value:** -0.7450 (var=0.0406)
**Predicted under pi_11:** -0.3375 (var=0.1583)
**Predicted under pi_10:** -0.8025 (var=0.0219)

### Experiment 13
**Design**
  A=[1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0, 1, 1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1, 0, 0, 1, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 0, 0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1, 0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 0, 1, 0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 1, 0, 1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    chose_a_c1 = []
    chose_a_c2 = []

    for _, row in data.iterrows():
        a = [int(v) for v in row['option_a_ratings']]
        b = [int(v) for v in row['option_b_ratings']]
        diff = [a[j] - b[j] for j in range(len(a))]

        t_top = int(sum(diff[:3]))
        l_late = int(sum(diff[-3:]))
        chose_a = 1.0 if int(row['response']) == 0 else 0.0

        if t_top == 3 and l_late == -3:
            chose_a_c1.append(chose_a)
        elif t_top == -3 and l_late == 3:
            chose_a_c2.append(chose_a)

    if len(chose_a_c1) == 0 or len(chose_a_c2) == 0:
        return 0.0

    return float(np.mean(chose_a_c2) - np.mean(chose_a_c1))
```

**Observed (real) value:** 0.0125 (var=0.0153)
**Predicted under pi_11:** 0.0150 (var=0.0434)
**Predicted under pi_10:** -0.0287 (var=0.0253)

### Experiment 14
**Design**
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0]

**Metric**
```python
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    def top_sum(ratings):
        ratings = list(ratings)
        return int(ratings[0]) + int(ratings[1]) + int(ratings[2]) + int(ratings[3])

    a_sum = data['option_a_ratings'].apply(top_sum)
    b_sum = data['option_b_ratings'].apply(top_sum)
    sub_tally = a_sum - b_sum

    chose_a = 1 - data['response']

    numerator = float((sub_tally * chose_a).sum())
    denominator = float(sub_tally[sub_tally > 0].sum())

    if denominator == 0.0:
        return 0.0
    return numerator / denominator

```

**Observed (real) value:** -0.6113 (var=0.0332)
**Predicted under pi_11:** -0.6597 (var=0.0070)
**Predicted under pi_10:** -0.7413 (var=0.0053)

### Experiment 15
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    a_last = data['option_a_ratings'].apply(lambda x: x[-1])
    b_last = data['option_b_ratings'].apply(lambda x: x[-1])
    last_diff = a_last - b_last
    chose_a = (data['response'] == 0).astype(float)

    pos_mask = last_diff > 0
    neg_mask = last_diff < 0
    if pos_mask.sum() == 0 or neg_mask.sum() == 0:
        return 0.0

    return float(chose_a[pos_mask].mean() - chose_a[neg_mask].mean())

```

**Observed (real) value:** -0.0008 (var=0.0093)
**Predicted under pi_11:** 0.2650 (var=0.0082)
**Predicted under pi_10:** -0.2821 (var=0.0067)

### Experiment 16
**Design**
  A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    a = np.asarray(data['option_a_ratings'].tolist(), dtype=float)
    b = np.asarray(data['option_b_ratings'].tolist(), dtype=float)

    positions = np.array([5.0, 6.0, 7.0])
    rho = 0.65
    weights = np.exp(rho * (positions - 7.0))
    weights = weights / weights.sum() * 3.0

    late_diff = a[:, 5:8] - b[:, 5:8]
    weighted_late_tally = late_diff @ weights

    chose_a = 1.0 - data['response'].to_numpy(dtype=float)
    return float(np.mean(weighted_late_tally * chose_a))
```

**Observed (real) value:** 0.2273 (var=0.0174)
**Predicted under pi_11:** 0.3376 (var=0.0151)
**Predicted under pi_10:** 0.3939 (var=0.0140)

### Experiment 17
**Design**
  A=[1, 1, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np


def metric(data: pd.DataFrame) -> float:
    rho = 0.6
    weights = np.exp(rho * (np.arange(6, dtype=float) - 5.0))
    n = 0
    total = 0.0
    for row in data.itertuples(index=False):
        a = np.asarray(row.option_a_ratings, dtype=float)
        b = np.asarray(row.option_b_ratings, dtype=float)
        late_diff = (a - b)[-6:]
        score = float(np.dot(weights, late_diff))
        if score > 0.0:
            total += 1.0 if row.response == 0 else 0.0
        elif score < 0.0:
            total += 1.0 if row.response == 1 else 0.0
        else:
            total += 0.5
        n += 1
    return 0.5 if n == 0 else total / n
```

**Observed (real) value:** 0.4479 (var=0.0016)
**Predicted under pi_11:** 0.4383 (var=0.0025)
**Predicted under pi_10:** 0.4319 (var=0.0016)

### Experiment 18
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    if len(data) == 0:
        return 0.5
    a = np.stack([np.asarray(x, dtype=float) for x in data['option_a_ratings']])
    b = np.stack([np.asarray(x, dtype=float) for x in data['option_b_ratings']])
    w8 = float(np.exp(-0.70))
    late_score = (a[:, 9] - b[:, 9]) + w8 * (a[:, 8] - b[:, 8])
    predicted = np.where(late_score > 0.0, 0, 1)
    response = data['response'].to_numpy(dtype=np.int64)
    valid = np.abs(late_score) > 1e-12
    if not np.any(valid):
        return 0.5
    return float(np.mean(response[valid] == predicted[valid]))

```

**Observed (real) value:** 0.2321 (var=0.0067)
**Predicted under pi_11:** 0.4623 (var=0.0038)
**Predicted under pi_10:** 0.3244 (var=0.0025)

### Experiment 19
**Design**
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]

**Metric**
```python
import numpy as np


def metric(data: pd.DataFrame) -> float:
    a_last = data['option_a_ratings'].apply(lambda x: int(x[5])).to_numpy(dtype=float)
    b_last = data['option_b_ratings'].apply(lambda x: int(x[5])).to_numpy(dtype=float)
    response = data['response'].to_numpy(dtype=float)

    a_has = (a_last == 1.0) & (b_last == 0.0)
    b_has = (a_last == 0.0) & (b_last == 1.0)
    valid = a_has | b_has

    if not np.any(valid):
        return 0.5

    target = np.zeros(len(data), dtype=float)
    target[b_has] = 1.0

    return float(np.mean((response[valid] == target[valid]).astype(float)))

```

**Observed (real) value:** 0.5054 (var=0.0014)
**Predicted under pi_11:** 0.4915 (var=0.0021)
**Predicted under pi_10:** 0.1546 (var=0.0026)

### Experiment 20
**Design**
  A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 1, 0, 0, 1, 0]  B=[0, 0, 0, 1, 1, 0, 1, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 0, 1, 0, 0, 1, 0]

**Metric**
```python
import numpy as np

def metric(data):
    a = np.array([np.asarray(x, dtype=float) for x in data['option_a_ratings']])
    b = np.array([np.asarray(x, dtype=float) for x in data['option_b_ratings']])
    early = a[:, :3] - b[:, :3]
    early_tally = early.sum(axis=1)
    resp = data['response'].to_numpy(dtype=float)
    positive = early_tally > 0.0
    negative = early_tally < 0.0
    if not np.any(positive) or not np.any(negative):
        return 0.0
    return float(resp[negative].mean() - resp[positive].mean())

```

**Observed (real) value:** 0.7250 (var=0.0401)
**Predicted under pi_11:** 0.4454 (var=0.0511)
**Predicted under pi_10:** 0.6158 (var=0.1036)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Across the two new experiments, pi_10 is clearly closer to the observed data: Exp1 observed 0.0433 (pi_10 0.0017 vs pi_11 0.8175), and Exp2 observed 0.0411 (pi_10 0.0783 vs pi_11 -0.0054). Pooling all 20 experiments, pi_10 also has the better aggregate fit: mean absolute error roughly 0.124 vs pi_11's 0.185, and RMSE roughly 0.175 vs pi_11's 0.330. pi_11's terminal-run/forced-triplet machinery generates large false effects in Exp1, Exp6, Exp12, Exp15, and Exp18, so it is not task-invariant. However pi_10 is not fully task-invariant either: it badly misses Exp19 (0.1546 vs observed 0.5054) and has moderate misses in Exp5, Exp10, Exp15, and Exp18. The overall observed pattern is more consistent with a simpler tally-dominant process: the full unweighted tally controls choice whenever it is nonzero, while only exact ties invoke a global, compressed validity-weighted tally; there is no strong evidence for run parsing, terminal priority, forced late-triplet routes, or recency/anti-recency. This would explain the near-zero terminal contrasts in Exp1/7/8/13/15/19, the small validity-weighted tie effects in Exp2/5/6, and the tally-driven reversals in Exp3/12/14/18/20. Neither current theory embodies this, so a new theory is warranted rather than a model tweak.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace pi_11 with a new 'tally-first, global compressed-validity tie-break' theory. The predict function should first compute d = sum(A - B). If d != 0, choice should follow sign(d) through a softmax with moderate inverse temperature and a small lapse, with sensitivity increasing in |d| but no segmentation. Only when d == 0 exactly should the model compute a global validity-weighted tally W = sum_i w_i (A_i - B_i), where w_i is a monotone but compressed function of advertised validity, e.g. w_i = w0 + (v_i - v_min)^gamma with small w0 and gamma around 0.5-1.0. Choice on ties should follow W through a softmax with moderate inverse temperature and lapse. The theory should explicitly exclude run detection, terminal priority, forced late-triplet openings, fallback pooling, and recency/anti-recency mechanisms. Parameter ranges should allow weak-to-moderate validity weighting and substantial noise so that Exp1 stays near chance, Exp2 gives a small positive validity-weighted effect, Exp5/6 give strong tie effects, Exp19 stays at chance, and full-tally dominance explains Exp3/12/14/18/20. This produces a cleaner competitor to pi_10 while retaining pi_10 as the incumbent."
}
```

## Usage

```json
{
  "input_tokens": 34856,
  "output_tokens": 10197,
  "reasoning_tokens": 8408,
  "provider": "CoreWeave"
}
```
