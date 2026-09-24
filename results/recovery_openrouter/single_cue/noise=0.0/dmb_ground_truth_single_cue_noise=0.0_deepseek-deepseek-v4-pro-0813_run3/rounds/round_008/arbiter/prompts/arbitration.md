# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_9" and "pi_10") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_9" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_10" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_9
People make binary-feature choices by a primary unweighted signed tally. When the tally is clear, choice follows the tally stochastically with a small lapse. When the tally is tied or near-tied, people parse the validity display into a single contiguous terminal perceptual chunk only when the validity sequence contains a structural boundary. In addition to large jumps, moderate positive and negative end discontinuities, and cumulative short-display contrasts, short displays have a fallback parsing rule: if no other boundary rule has opened a chunk, the largest adjacent validity discontinuity defines the terminal chunk. A targeted forced late-pool rule is added for very short displays: when a flat high-validity early triplet is followed by a lower, homogeneous late triplet, that late block is opened with bounded decisiveness, producing recency-weighted choices against the early high-validity pool. Recency inside any chunk remains a weak linear ramp with a cap, not an exponential validity-times-position re-ranking, and large displays with small tallies remain low-confidence.

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
    positions = np.arange(n_features, dtype=float)

    def stable_softmax(scores, inv_temp):
        scores = np.asarray(scores, dtype=float)
        z = inv_temp * (scores - np.max(scores))
        z = np.clip(z, -30.0, 30.0)
        e = np.exp(z)
        return e / np.sum(e)

    def lapse_mix(core, eps):
        probs = (1.0 - eps) * core + eps * np.array([0.5, 0.5])
        probs = np.clip(probs, 0.005, 0.995)
        total = float(np.sum(probs))
        if total <= 1e-12:
            return np.array([0.5, 0.5])
        return probs / total

    def find_block():
        n = n_features
        v = validities
        vmin = float(np.min(v))
        vmax = float(np.max(v))
        spread = max(vmax - vmin, 1e-9)
        candidates = []

        gap_hi = float(parameters['gap_hi'])
        gap_lo = float(parameters['gap_lo'])
        gap_pos_max = float(parameters['gap_pos_max'])
        drop_lo = float(parameters['drop_lo'])
        drop_hi = float(parameters['drop_hi'])
        flat_tol = float(parameters['flat_tol'])
        block_max_large = int(parameters['block_max_large'])
        block_max_small = int(parameters['block_max_small'])
        moderate_allowed = n <= int(parameters['moderate_max_features'])

        for size in range(2, min(block_max_large, n - 1) + 1):
            i = n - size - 1
            if i < 0:
                continue
            jump = float(v[i + 1] - v[i])
            block_vals = v[i + 1:]
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
                    'start': i + 1,
                    'size': size,
                    'jump': jump,
                    'contrast': abs(jump),
                    'block_vals': block_vals,
                    'block_range': block_range,
                    'direction': direction,
                    'kind': kind
                })

        if n <= int(parameters['short_max_features']):
            cum_lo = float(parameters['cum_lo'])
            cum_hi = float(parameters['cum_hi'])
            cum_late_flat = float(parameters['cum_late_flat_tol'])
            cum_prev_flat = float(parameters['cum_prev_flat_tol'])
            for k in (3, 2):
                if n < 2 * k:
                    continue
                prev = v[n - 2 * k:n - k]
                late = v[n - k:]
                late_range = float(np.max(late) - np.min(late))
                prev_range = float(np.max(prev) - np.min(prev))
                contrast = float(np.mean(prev) - np.mean(late))
                if (cum_lo <= contrast <= cum_hi and
                        late_range <= cum_late_flat and
                        prev_range <= cum_prev_flat):
                    candidates.append({
                        'start': n - k,
                        'size': k,
                        'jump': contrast,
                        'contrast': contrast,
                        'block_vals': late,
                        'block_range': late_range,
                        'direction': -1,
                        'kind': 'cumulative_late'
                    })

        if n <= int(parameters['forced_max_features']):
            forced_lo = float(parameters['forced_contrast_lo'])
            forced_hi = float(parameters['forced_contrast_hi'])
            forced_late_flat = float(parameters['forced_late_flat_tol'])
            forced_prev_flat = float(parameters['forced_prev_flat_tol'])
            forced_alt = float(parameters['forced_altitude_lo'])
            forced_gain = float(parameters['forced_gain'])
            k = 3
            if n >= 2 * k:
                prev = v[n - 2 * k:n - k]
                late = v[n - k:]
                contrast = float(np.mean(prev) - np.mean(late))
                late_range = float(np.max(late) - np.min(late))
                prev_range = float(np.max(prev) - np.min(prev))
                if (forced_lo <= contrast <= forced_hi and
                        late_range <= forced_late_flat and
                        prev_range <= forced_prev_flat and
                        float(vmax - np.mean(late)) >= forced_alt):
                    candidates.append({
                        'start': n - k,
                        'size': k,
                        'jump': contrast,
                        'contrast': contrast,
                        'block_vals': late,
                        'block_range': late_range,
                        'direction': -1,
                        'kind': 'forced_late_pool',
                        'gain_override': forced_gain
                    })

        if not candidates and n <= int(parameters['short_max_features']):
            short_drop_min = float(parameters['short_drop_min'])
            jumps = np.diff(v)
            order = np.argsort(-np.abs(jumps), kind='stable')
            for jpos in order:
                jpos = int(jpos)
                size = n - (jpos + 1)
                if size < 2 or size > block_max_large:
                    continue
                jump = float(v[jpos + 1] - v[jpos])
                if abs(jump) < short_drop_min:
                    continue
                late_vals = v[jpos + 1:]
                candidates.append({
                    'start': jpos + 1,
                    'size': size,
                    'jump': jump,
                    'contrast': abs(jump),
                    'block_vals': late_vals,
                    'block_range': float(np.max(late_vals) - np.min(late_vals)),
                    'direction': 1 if jump > 0.0 else -1,
                    'kind': 'largest_drop_short'
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

        best = max(candidates, key=lambda c: (c['kind'] == 'forced_late_pool', c['gain'], c['contrast'], -c['size']))
        return best

    tau_tie = float(parameters['tau_tie'])

    if abs(tally) <= tau_tie:
        block = find_block()
        if block is not None and block['size'] >= 2:
            idx = np.arange(block['start'], block['start'] + block['size'], dtype=int)
            size = int(block['size'])
            rel = (positions[idx] - float(np.min(positions[idx]))) / max(1.0, float(size - 1))

            is_forced = block.get('kind') == 'forced_late_pool'
            if is_forced:
                forced_slope = float(parameters['forced_recency_slope'])
                forced_cap = float(parameters['forced_recency_cap'])
                ramp = 1.0 + np.minimum(forced_slope * rel, forced_cap)
            else:
                slope = float(parameters['recency_slope'])
                cap = float(parameters['recency_cap'])
                ramp = 1.0 + np.minimum(slope * rel, cap)

            w = ramp
            denom = float(np.sum(w))
            if denom <= 1e-12:
                w = np.ones_like(w)
            else:
                w = w / denom * float(size)

            sub_tally = float(np.dot(w, diff[idx]))

            beta_sub = float(parameters['beta_sub'])
            beta_eff = float(np.clip(beta_sub * block['gain'], 0.05, 2.0))

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
        return np.array([0.5, 0.5])

    beta_small = float(parameters['beta_tally_small'])
    beta_large = float(parameters['beta_tally_large'])
    epsilon_small = float(parameters['epsilon_tally_small'])
    epsilon_large = float(parameters['epsilon_tally_large'])
    frac = float(np.clip((n_features - 8.0) / 7.0, 0.0, 1.0))
    beta_tally = beta_small + frac * (beta_large - beta_small)
    epsilon_tally = epsilon_small + frac * (epsilon_large - epsilon_small)

    near_bound = float(parameters['near_bound'])
    n_low_conf = int(parameters['n_low_conf'])
    low_conf = (n_features >= n_low_conf) and (abs(tally) <= near_bound)

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


## EXPERIMENT 1 (proposed by pi_9)

### DESIGN
**Validities (n_features=6):** [1.0, 1.0, 1.0, 0.9, 0.5, 0.5]

**Trial pairs (n=12):**
  trial 1: A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  trial 2: A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  trial 3: A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  trial 4: A=[0, 1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  trial 5: A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  trial 6: A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  trial 7: A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  trial 8: A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  trial 9: A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  trial 10: A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  trial 11: A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  trial 12: A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]

**Rationale:** Six-feature design targeting the forced late-pool difference. The validity vector [1.0, 1.0, 1.0, 0.9, 0.5, 0.5] has a flat high early triplet and a lower late triplet with mean 0.633 and range 0.40, satisfying both models' forced late-pool opening conditions on every trial. All 12 unique pairs are exact unweighted tally ties, so the primary tally is silent and both models enter the forced terminal-chunk branch at display positions 3-5. Inside that opened chunk the advocated model uses its forced recency ramp with normalized position weights 0.4, 1.0, 1.6, so the last late feature dominates. The competing model instead uses validity-ordered weights; the first late feature has validity 0.9 while the last two are 0.5, so across its full parameter ranges the first late feature receives more weight than the middle and last late features combined. Every pair puts the first and last late features in conflict, with the middle late feature varied, while the early features only balance the total tally. Thus the advocated model predicts p(A) follows the last late feature, whereas the competing model predicts p(A) follows the first late feature: a per-trial sign reversal. Trials 1-6 have the first late feature favoring B and the last late feature favoring A; trials 7-12 are their A/B mirrors for bias control. Twelve unique pairs repeated eight times gives 96 trials.

**Computed schedule:** 12 unique pairs × 8 reps = 96 trials per subject.



### METRIC
Rationale:
The forced late-pool branch is triggered on every trial by the validity schedule, so the only relevant difference between theories is how the three late features (indices 3, 4, 5) are weighted. The advocated theory uses a forced recency ramp with normalized weights 0.4, 1.0, 1.6, so choices should track the last late feature at index 5. The competing theory uses validity-ordered weights, giving the largest weight to the first late feature at index 3, which is always in conflict with the last late feature in this schedule. The metric therefore measures the proportion of choices congruent with the last late feature; the theories predict clearly different values, near high for the advocated theory and near low for the competing theory.

Source:
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


### RESULTS
- Predicted under pi_9 (simulated): 0.7083 (var=0.0026)
- Predicted under pi_10 (simulated): 0.1546 (var=0.0026)
- Observed on real data: 0.5054 (var=0.0014)

## EXPERIMENT 2 (proposed by pi_10)

### DESIGN
**Validities (n_features=10):** [0.6, 0.65, 0.7, 0.75, 0.8, 0.85, 0.9, 0.95, 0.98, 0.99]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]
  trial 2: A=[1, 1, 1, 0, 1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 0, 1, 1]
  trial 3: A=[1, 1, 1, 1, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0, 1, 1]
  trial 4: A=[1, 1, 1, 0, 0, 1, 0, 0, 1, 0]  B=[0, 0, 0, 1, 1, 0, 1, 1, 0, 1]
  trial 5: A=[0, 0, 0, 0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 1, 0, 1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0, 0, 1, 0, 0]
  trial 7: A=[0, 0, 0, 0, 1, 1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 1, 0, 0]
  trial 8: A=[0, 0, 0, 1, 1, 0, 1, 1, 0, 1]  B=[1, 1, 1, 0, 0, 1, 0, 0, 1, 0]

**Rationale:** This design isolates a structural difference in the no-terminal-chunk, tied-tally path. The validity ladder uses adjacent steps of only 0.05, below both theories' smallest boundary thresholds (positive-end lower bound 0.06, negative-drop lower bound 0.10, large-jump lower bound 0.34), and n_features=10 disables the short-display cumulative, forced, and largest-drop routes. Therefore neither theory opens a terminal chunk, and the competing theory predicts p(A)=0.50 on every tied trial. The advocated theory instead has a preceding-block pooling route for 8-11 feature displays when no terminal chunk opens. With this validity ladder, its pool parser cuts off the earliest coherent run after the first 3, 4, or 5 positions depending on pool_flat_tol, and both pool_rank settings (earliest and largest) select that first run. All trial pairs are exact unweighted tally ties, so the primary tally is silent. Trials 1-4 put that early pooled prefix in favor of A, giving advocated p(A) above 0.5 (ranging from about 0.63 to 0.90 depending on the opened prefix and pool parameters), while trials 5-8 are A/B mirrors and give p(A) below 0.5. The competing theory is flat at chance for all eight pairs, producing a mirrored high/low versus flat-at-chance quantitative dissociation. Eight unique pairs repeated 12 times gives 96 trials per subject and the mirrored block controls response bias.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
All eight trial pairs have an exact unweighted tally tie, so the competing theory predicts chance choices for every pair. The advocated theory predicts that its fallback earliest-coherent-pool route weights the first 3 to 5 validity positions, and the first three positions are always unanimously aligned with one option in every trial pair. This metric therefore classifies each trial by the first three features: if those positions favor A, early_tally is positive; if they favor B, early_tally is negative. It returns the B-choice rate on early-B trials minus the B-choice rate on early-A trials. Under the advocated theory this is large and positive because early-B trials should yield mostly B choices and early-A trials should yield mostly A choices. Under the competing theory both rates remain near 0.5, giving a value near zero. Using 48 trials per early direction per subject makes the per-subject estimate tight.

Source:
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


### RESULTS
- Predicted under pi_9 (simulated): 0.0171 (var=0.0102)
- Predicted under pi_10 (simulated): 0.6158 (var=0.1036)
- Observed on real data: 0.7250 (var=0.0401)

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
**Predicted under pi_9:** -0.7143 (var=0.0034)
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
**Predicted under pi_9:** 0.0876 (var=0.0000)
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
**Predicted under pi_9:** 2.9833 (var=0.0067)
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
**Predicted under pi_9:** 4.2816 (var=0.3801)
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
**Predicted under pi_9:** -0.0250 (var=0.0478)
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
**Predicted under pi_9:** -0.0274 (var=0.0303)
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
**Predicted under pi_9:** -0.3860 (var=0.0082)
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
**Predicted under pi_9:** 0.9845 (var=0.9845)
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
**Predicted under pi_9:** 0.0408 (var=0.0098)
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
**Predicted under pi_9:** -0.7875 (var=0.0252)
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
**Predicted under pi_9:** -0.0525 (var=0.0340)
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
**Predicted under pi_9:** -0.7277 (var=0.0070)
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
**Predicted under pi_9:** 0.0112 (var=0.0091)
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
**Predicted under pi_9:** 0.3795 (var=0.0133)
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
**Predicted under pi_9:** 0.4844 (var=0.0030)
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
**Predicted under pi_9:** 0.4990 (var=0.0023)
**Predicted under pi_10:** 0.3244 (var=0.0025)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "The two theories are close on many shared primary-tally experiments (E3-E6, E10-E14, E16-E17), so the core full-tally-plus-tie-chunk architecture has some validity. But the experiments designed to separate the theories show that neither is task-invariant. E2 is a decisive win for pi_10: observed early-block diagnostic 0.7250, pi_10 0.6158, pi_9 0.0171. E18 and E9 also favor pi_10: E18 observed 0.2321 vs pi_10 0.3244 vs pi_9 0.4990; E9 observed -0.5522 vs pi_10 -0.5471 vs pi_9 -0.3860. However, E1 rejects the specific within-chunk mechanisms in both theories: observed 0.5054, while pi_9's forced recency predicts 0.7083 and pi_10's validity-order weighting predicts 0.1546. The observed value suggests the late block is opened but its features are not preferentially weighted by either recency or validity order. E15 and E17 also fail to show the within-chunk late-cue weighting that distinguishes the two theories. Overall pi_10 is the better incumbent because it captures the early coherent-block fallback that appears strongly in the data, but neither theory explains all experiments.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace pi_9 with a boundary-parsing, equal-weight-segment theory. Keep the primary unweighted full tally for clear tallies. On ties or near-ties, segment the validity vector into contiguous coherent runs using validity discontinuities. Select, in order: (1) a terminal segment if one opens, including forced late-triplet openings on short displays; (2) otherwise the earliest coherent preceding segment; (3) otherwise remain at chance or use the low-confidence full tally. Critically, once a segment is selected, use only the unweighted signed sub-tally of that segment: all features inside the selected segment receive equal weight, with no recency ramp and no validity-ordered cue weighting. Validity differences affect only whether a segment is recognized and how decisively it drives the softmax/lapse, not the relative weights inside the segment. This should fix E1 by producing chance inside the non-flat forced late chunk, preserve pi_10's early-fallback successes in E2/E9/E18, and reduce the over-extreme late-weighted predictions in E15/E16/E17 while retaining the high-validity terminal-block effects in E5/E6."
}
```

## Usage

```json
{
  "input_tokens": 30177,
  "output_tokens": 15268,
  "reasoning_tokens": 14698,
  "provider": "AtlasCloud"
}
```
