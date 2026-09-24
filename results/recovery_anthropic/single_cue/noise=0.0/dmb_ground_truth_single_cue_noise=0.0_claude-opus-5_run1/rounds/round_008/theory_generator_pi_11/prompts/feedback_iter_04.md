# feedback_iter_04

## System Prompt

You are a renowned cognitive scientist critiquing a freshly proposed candidate theory and model in the Decision Making (Binary Features) domain.

The candidate has been simulated on every previously run experiment. For each experiment you are shown the design, the metric, the value the metric takes on real data, and the value it takes on the candidate's simulated data.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the feedback is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across multiple experiments. 
Your task is to determine whether the candidate captures the human/real behavior well enough across these experiments. Return a verdict:
  * "continue"   — the candidate is good enough; carry on.
  * "regenerate" — the candidate fails to capture the empirical pattern; the proposing agent must produce a new candidate, taking your rationale into account.

Justify the verdict with a concrete diagnosis (which experiments fail, in what direction, what mechanism is likely missing or miscalibrated).

## SCOPE OF YOUR CRITIQUE — STAY INSIDE THE ARBITER'S MECHANISM FAMILY
When an "## ARBITER RECOMMENDATION" block is present below, the proposer was explicitly instructed to implement the mechanism family the arbiter prescribed. Your job is to grade FIT QUALITY *within that prescribed family*, not to relitigate which family should be used — that is the arbiter's call, made one level above this loop.

Concretely:
  * If the candidate misses the data, you may push for MINOR ADJUSTMENTS that keep the prescribed mechanism intact: tightening / widening parameter ranges, adding a temperature, swapping a normalization scheme, fixing a softmax / distance metric, re-balancing attention weights, fixing a learning-rate sign, correcting a bug in the gating or recurrence, etc.
  * You MUST NOT recommend switching to a different mechanism family. Such a switch is the arbiter's prerogative; recommending it here will mislead the proposer into oscillating between families across iterations.
  * Also grade FAITHFULNESS to the recommendation explicitly: if the candidate has clearly drifted into a different family than the one prescribed, say so in the rationale and ask for a return to the prescribed family — again, with minor adjustments, not a re-design.

## ACCEPT GATE — HOW THE LOOP DECIDES WHAT TO BUILD ON NEXT
This propose-loop has a programmatic accept gate. After every iteration the candidate's `aggregate_loss` is compared against the running-best loss (`accepted_loss`):
  * `loss < accepted_loss` → ACCEPTED. The candidate becomes the new running-best base; the next iteration's proposer will build on THIS candidate.
  * `loss >= accepted_loss` → REJECTED. The base is unchanged; the next iteration's proposer will build on the SAME `accepted` candidate again, with your new feedback on top. Rejected candidates are discarded — the loop guarantees the base never regresses, so you do NOT need to ask the proposer to "revert" anything; that already happens for free.

Two consequences for your verdict:
  * If the candidate you are grading was REJECTED by the gate, returning `"continue"` is silently downgraded to `"regenerate"` (returning a worse candidate would defeat the gate). Spend your rationale on a NEW direction the proposer should try on top of the unchanged accepted base, not on defending the rejected attempt.
  * If the candidate was ACCEPTED, you can return `"continue"` to stop the loop and ship this candidate, or `"regenerate"` to keep tuning further.

## LEARN FROM YOUR OWN PAST ADVICE
When a "## YOUR PRIOR CRITIQUES" block is present below, each prior iteration ends with an "Outcome of your advice" line that says whether the next candidate the proposer produced was ACCEPTED (your advice helped — its loss strictly beat the running best) or REJECTED (your advice didn't help — the proposer discarded the result and reset to the previous accepted base). This is the loop's ground-truth signal on whether *your own previous critique was good*. Use it explicitly:
  * If a previous piece of advice was ACCEPTED, it is OK to repeat / extend it. Reinforce in the same direction.
  * If a previous piece of advice was REJECTED, do NOT repeat the same recommendation; in your new rationale, briefly acknowledge that the previous push in that direction was rejected by the gate and try a different in-family knob (or a smaller step in the same direction) instead.
  * If you find yourself oscillating (e.g. iter 1 said "increase α", iter 2 said "decrease α", iter 3 about to say "increase α" again), STOP and recommend a value between the two flanking iterations instead.
  * The "## LOSS TRAJECTORY" block at the top of the user prompt summarises the same information at the loop level — consult it before issuing a new regenerate-with-direction recommendation.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## ARBITER RECOMMENDATION (mechanism family the proposer was told to implement)
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_7`
- THEORY 2 = `pi_10`
- The recommendation below acts on THEORY 1 (= `pi_7`).

Replace pi_7 (MDSC-NV) entirely. Its two signature claims are falsified: (a) 'coalitions buy nothing / near-argmax relative doubt' is refuted by Exps 1 (.49), 15 (.55), 16 (.47) and by Exp 2's C-term; (b) the raw display-length lapse rho^(m-2) is refuted by the flat, high anchor-follow rates on long displays (Exp 2 T-term, Exps 17/18).

Propose instead a RELATIVE-SHARE GATING theory — call it SSG (Salience-Share Gating) — that is a strong competitor to pi_10 rather than a weak one:

1. Row salience over DISCRIMINATING rows only: s_j = (1-v_j)^gamma * exp(lam*j), gamma ~ 1.5-2.5, lam ~ 0.1-0.5 (weak recency; large lam only needed in the near-tied-validity designs of Exps 10/11).
2. GRADED MODE GATE driven by the salience SHARE of the top row, not an absolute validity threshold: pi_one = sigmoid((s_max/sum_j s_j - c)/w), with c ~ 0.55-0.75, w ~ 0.05-0.15. Intuition: a subject abandons integration only when one dissent is *conspicuously odder than everything else on the screen*. This reproduces pi_10's key successes — a .52 expert among .64-.96 experts has share ~.6-.8 -> one-reason, high and flat in coalition size (Exps 2-T, 17, 18); a .66/.68 expert among .64/.70/.72 experts has share ~.3-.4 -> compensatory, hence at/below chance against a coalition (Exps 1, 15, 16) — but WITHOUT the implausible knife edge, and it makes a distinct, testable prediction pi_10 cannot make: a .68 dissenter standing alone against a single .96 row should still be followed (its share is high), whereas pi_10 says compensatory there. It should also shrink the Exp-4 swing (least-valid .55 sits next to .60, so share is low, mode is mostly compensatory) which is pi_10's clearest quantitative miss.
3. One-reason limb: follow the top-salience row with fidelity (1-eps_t) degraded only by the size of the opposing coalition (rho_opp^(k_conf-1)), NOT by display length — matching the observed flatness.
4. Compensatory limb: divisively normalised anti-validity sum E = sum(sign_j * s_j)/(sigma + sum s_j), p = sigmoid(beta*E), with a mild conflict (not length) cost; calibrate so unanimous 5-6 row displays land near .74 (Exp 7) rather than at ceiling.
5. Keep the label-degeneracy/tally fallback only for exact repeats (tolerance .002) so the .004/.005-gap designs (Exps 10, 11) still run the salience rule with strong recency.

Target quantitative anchors for the new model: Exp 1 ~.49, Exp 2 (T-C) ~.32, Exp 15 ~.55, Exp 16 ~.47, Exp 17 ~.86, Exp 18 ~.83, Exp 7 ~.74, Exp 4 ~.17, Exp 13 ~.59, Exps 3/5/6/12/14 in the .15-.42 anti-validity range.


## CANDIDATE THEORY
**SSG-5 — Salience-Share Gating with an opposition-graded adjudication limb.**

The architecture is exactly SSG-4's; one quantitative commitment is revised, none is reversed.

**(1) Two modes: adjudication vs. integration.** On every trial the subject either lets ONE expert adjudicate the choice or integrates all disagreeing rows. Mode is decided by a RELATIVE quantity — the share of the display's total *oddness* owned by genuinely near-chance experts — not by display length nor by an absolute knife edge. Each discriminating row has oddness o_j = (1-v_j)^gamma_s (gamma_s ≈ 6.4-8.6, a contrast-enhanced, nearly ordinal 'who is the strangest expert here' read-out) and a scandal value g_j = sigmoid((v_crit - v_j)/w_h) with a crisp boundary (w_h ≈ .008-.011, v_crit ≈ .576-.586). The gate is share = Σ_j g_j·o_j / Σ_j o_j and pi_one = (max_j g_j)·[f + (1-f)·sigmoid((share - c)/w)]: adjudication requires BOTH that some expert be near-chance AND that near-chance experts own most of the display's oddness.

**(2) REVISED — adjudication is faithful but NOT flat in opposition; it is flat only in display length.** When a near-chance expert commands the trial, subjects follow its verdict with high fidelity (eps_t ≈ .19-.29) and scanning extra, silent or agreeing rows costs nothing at all — one-reason choice is free in sheer list length, which is why anchor-follow rates stay high on six-row displays. What it is NOT free in is genuine CONTRADICTION: each additional row that argues the other way beyond the first charges rho_opp ≈ .82-.90. A scandalous dissenter standing alone against one opposing voice is followed almost as often as a scandalous dissenter in a unanimous display, but once two or three experts are lined up the other way the adjudication itself becomes contested and the verdict is dragged appreciably toward chance. This is a *moderate* opposition discount, intermediate between a flat limb and a compounding one: it leaves the lone-anchor designs untouched while preventing the 2-vs-2 and 2-vs-3 conflict displays from producing near-deterministic anti-validity choices. Among co-scandalous rows the consulted verdict is drawn from softmax(log g_j + mu·j) with a WEAK positional gain (mu ≈ .35-.62); reading order can never lift an ordinary expert over a near-chance one.

**(3) Integration is specifically fragile under DISAGREEMENT.** When the gate is shut, evidence is integrated with w_j = (1-v_j)^gamma_w·exp(lam·j) (gamma_w ≈ 1.32-1.58, lam ≈ .10-.17, so doubt, not position, buys weight), divisively normalised to the loudest dissent, E = Σ sign_j·ŵ_j/(sigma + Σ ŵ_j), p = sigmoid(beta·E). The retained evidence leaks with display load (rho_m) and much more steeply with every additional row that argues the other way (rho_c ≈ .62-.75 per minority row). Holding two mutually contradicting coalitions in mind is the expensive operation; no conflict display ever reaches a near-deterministic anti-validity verdict.

The theory's signature is therefore that BOTH modes are degraded by contradiction and NEITHER is degraded by list length — they differ only in how steeply contradiction bites (mild for adjudication, severe for integration). When all discriminating experts agree there is nothing to adjudicate (pi_one = 0) and only the load leak applies. If two printed validities are indistinguishable (gap < .002) oddness has no referent and choice collapses to a graded unweighted row tally. No feedback is given, so the rule is stationary across the block.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # SSG: Salience-Share Gating
    import numpy as np

    # ---------- parse the (2, n_features) stimulus robustly ----------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(state['option_a_ratings'], dtype=float).ravel()
            b = np.asarray(state['option_b_ratings'], dtype=float).ravel()
        else:
            vals = list(state.values())
            if len(vals) >= 2:
                a = np.asarray(vals[0], dtype=float).ravel()
                b = np.asarray(vals[1], dtype=float).ravel()
    if a is None or b is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 2 and arr.shape[0] == 2:
            a, b = arr[0].ravel(), arr[1].ravel()
        elif arr.ndim == 2 and arr.shape[1] == 2:
            a, b = arr[:, 0].ravel(), arr[:, 1].ravel()
        elif arr.ndim == 1:
            h = arr.shape[0] // 2
            a, b = arr[:h], arr[h:2 * h]
        else:
            f = np.asarray(arr, dtype=float).reshape(2, -1)
            a, b = f[0].ravel(), f[1].ravel()

    n = int(min(np.size(a), np.size(b)))
    if n == 0:
        return np.array([0.5, 0.5])
    a = np.asarray(a, dtype=float)[:n]
    b = np.asarray(b, dtype=float)[:n]

    # ---------- printed validities ----------
    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None
    if v_raw is None:
        v = np.linspace(0.95, 0.55, n)
    else:
        v = np.asarray(v_raw, dtype=float).ravel()
        if v.size < n:
            v = np.concatenate([v, np.full(n - v.size, 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5, 0.9995)

    # ---------- parameters ----------
    gamma_s = float(parameters['gamma_s'])
    v_crit = float(parameters['v_crit'])
    w_h = float(max(float(parameters['w_h']), 1e-4))
    c_share = float(parameters['c_share'])
    w_share = float(max(float(parameters['w_share']), 1e-4))
    floor = float(np.clip(float(parameters['gate_floor']), 0.0, 1.0))
    mu = float(parameters['mu'])
    eps_t = float(np.clip(float(parameters['eps_t']), 0.0, 1.0))
    rho_opp = float(np.clip(float(parameters['rho_opp']), 1e-6, 1.0))
    gamma_w = float(parameters['gamma_w'])
    lam = float(parameters['lam'])
    sigma = float(max(float(parameters['sigma']), 1e-6))
    beta = float(parameters['beta'])
    eps0 = float(np.clip(float(parameters['eps0']), 0.0, 1.0))
    rho_m = float(np.clip(float(parameters['rho_m']), 1e-6, 1.0))
    rho_c = float(np.clip(float(parameters['rho_c']), 1e-6, 1.0))
    kappa = float(parameters['tally_kappa'])

    def sig(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # ---------- discriminating rows ----------
    diff = a - b
    disc = np.nonzero(diff != 0.0)[0]
    m = int(disc.size)
    if m == 0:
        return np.array([0.5, 0.5])
    signs = np.sign(diff[disc])
    n_a = float(np.sum(signs > 0.0))
    n_b = float(m) - n_a
    k_conf = int(min(n_a, n_b))

    # ---------- leak on the integration limb ----------
    keep_c = (1.0 - eps0) * (rho_m ** max(m - 2, 0)) * (rho_c ** k_conf)
    keep_c = float(min(max(keep_c, 0.0), 1.0))

    # ---------- label-degeneracy gate ----------
    degenerate = False
    if n > 1:
        vs = np.sort(v)
        if bool(np.any(np.diff(vs) < 2.0e-3)):
            degenerate = True

    if degenerate:
        p_core = sig(kappa * (n_a - n_b))
        p_a = 0.5 + keep_c * (p_core - 0.5)
        p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
        p = np.array([p_a, 1.0 - p_a], dtype=float)
        return p / p.sum()

    vd = v[disc]
    jd = disc.astype(float)

    # ---------- scandal values and sharpened oddness ----------
    zz = np.clip((v_crit - vd) / w_h, -60.0, 60.0)
    g = 1.0 / (1.0 + np.exp(-zz))                       # near-chance "scandal" weight
    log_g = -np.logaddexp(0.0, -zz)                     # stable log sigmoid
    log_o = gamma_s * np.log(np.clip(1.0 - vd, 1e-12, None))
    log_o_shift = log_o - np.max(log_o)
    o = np.exp(np.clip(log_o_shift, -700.0, 0.0))
    o_sum = float(np.sum(o))
    if (not np.isfinite(o_sum)) or o_sum <= 0.0:
        o = np.ones(m, dtype=float)
        o_sum = float(m)

    share = float(np.sum(g * o) / o_sum)
    g_share = sig((share - c_share) / w_share)
    P_trig = float(np.clip(np.max(g), 0.0, 1.0))

    # unanimous displays need no adjudication
    if k_conf == 0:
        pi_one = 0.0
    else:
        pi_one = P_trig * (floor + (1.0 - floor) * g_share)
    pi_one = float(np.clip(pi_one, 0.0, 1.0))

    # ---------- which row adjudicates (recency only breaks scandal ties) ----------
    sc = log_g + mu * jd
    sc = sc - np.max(sc)
    ww = np.exp(np.clip(sc, -700.0, 0.0))
    ws = float(np.sum(ww))
    if (not np.isfinite(ws)) or ws <= 0.0:
        ww = np.full(m, 1.0 / m)
    else:
        ww = ww / ws
    p_or_a = float(np.sum(ww[signs > 0.0]))
    fid = (1.0 - eps_t) * (rho_opp ** max(k_conf - 1, 0))
    fid = float(min(max(fid, 0.0), 1.0))
    p_one_a = 0.5 + fid * (p_or_a - 0.5)

    # ---------- integration limb ----------
    logw = gamma_w * np.log(np.clip(1.0 - vd, 1e-12, None)) + lam * jd
    logw = logw - np.max(logw)
    wi = np.exp(np.clip(logw, -700.0, 0.0))
    wsum = float(np.sum(wi))
    if (not np.isfinite(wsum)) or wsum <= 0.0:
        wi = np.ones(m, dtype=float)
        wsum = float(m)
    E = float(np.sum(signs * wi)) / (sigma + wsum)
    p_comp = sig(beta * E)
    p_c_a = 0.5 + keep_c * (p_comp - 0.5)

    # ---------- mixture ----------
    p_a = pi_one * p_one_a + (1.0 - pi_one) * p_c_a
    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
    p = np.array([p_a, 1.0 - p_a], dtype=float)
    return p / p.sum()

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0.0:
        return int(np.random.randint(len(probs)))
    probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- gamma_s: [6.4, 8.6]
- v_crit: [0.576, 0.586]
- w_h: [0.008, 0.011]
- c_share: [0.69, 0.75]
- w_share: [0.040, 0.065]
- gate_floor: [0.33, 0.47]
- mu: [0.35, 0.62]
- eps_t: [0.19, 0.29]
- rho_opp: [0.82, 0.90]
- gamma_w: [1.32, 1.58]
- lam: [0.10, 0.17]
- sigma: [0.58, 0.78]
- beta: [2.15, 2.65]
- eps0: [0.22, 0.30]
- rho_m: [0.87, 0.93]
- rho_c: [0.62, 0.75]
- tally_kappa: [0.7, 1.3]
- validities: validities

`rationale`:
MINIMAL DIFF: `predict` and `policy` are re-emitted byte-for-byte. Exactly ONE parameter range moves — the critic's item 1, and nothing else.

Edit — rho_opp [0.88, 0.96] -> [0.82, 0.90]. Because fid = (1-eps_t)*rho_opp^(k_conf-1), this term is *identically inert* whenever the adjudicating row faces at most one opposing voice, and bites only when a real coalition contradicts it. That inertness profile is exactly matched to the current residual structure:

- INERT on everything that is already right or that I do not want to give back: Exp 15 (anchor is the lone dissenter, k_conf = 1), Exp 18's T-term (the metric filters to k_conf <= 1 by construction), Exps 13/14 (lone dissenter, k_conf = 1), Exp 5 and all dominance trials (k_conf = 0, pi_one = 0), Exp 17 (the .66 row is not scandalous, so the gate is shut and the adjudication limb never runs). The two gains that iter 4 actually delivered — Exp 15 .807 and Exp 18 T-C .2975 — are therefore fully protected.
- CORRECTIVE exactly where the model is over-decided: Exp 16's metric selects trials with >= 2 late rows opposing the .52 anchor (currently +.035 too high) and Exp 8's diagnostic trials are majority-vs-salient-row splits with k_conf >= 2 (currently +.037 too high). At k_conf = 2-3 the fidelity multiplier drops from ~.92-.85 to ~.86-.74, pulling both down by roughly .03.
- SAME SIGN on the under-shot anti-validity cluster: Exps 1, 3 and 12 are dominated by 2-vs-2 and 3-vs-2 displays in which a near-chance row makes P_trig ~ 1, so (as the critic correctly diagnosed) they are ADJUDICATION trials that rho_c and sigma literally cannot reach. Only the opposition discount inside the adjudication limb can drag them toward chance, and all three are under-shot in the same direction (-.032, -.062, -.063).

This is a deliberate partial reversal of my iter-1 flattening, and I flag it as such: iter 2's own diagnostics established that flattening was NOT what fixed Exp 15 (rho_opp is inert there), so the iter-1 gain must be attributed to the accompanying eps_t/w_h moves, and the flattening itself is now unpaid-for cost on the k_conf >= 2 designs. I stop at .82-.90 rather than going lower because Exp 9 (.8078 vs .8189) is already marginally low and will follow Exp 8 down; the chosen midpoint (~.86) recovers the coalition-size shaping without over-shooting past the pre-iter-1 level.

Per the critic I explicitly did NOT touch: rho_c or sigma (both already tried and structurally unable to reach Exps 3/12), eps_t (its last drop is what bought Exps 15/18; this edit recovers its cost on the coalition designs without giving back that benefit), c_share/w_share/gate_floor (they buy Exps 2 and 4, pi_10's two clearest failures), gamma_w/lam (delivering Exps 10/11/14/17), w_h/v_crit, and mu (further spreading would hurt Exp 9). Exps 13 and 14 are treated as a jointly irreducible pair straddling chance with large between-subject variance; no new term is introduced to separate them.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.0672 -> ACCEPTED
- iter 2: loss=0.0600 -> ACCEPTED
- iter 3: loss=0.0506 -> ACCEPTED
- iter 4: loss=0.0451 -> ACCEPTED
- iter 5 (current candidate you are grading): loss=0.0422 -> ACCEPTED
Running-best (last accepted) base: iter 5 at loss=0.0422.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """One-reason adherence on model-disagreement trials.

    For every trial we compute (a) the option favoured by the FIRST
    discriminating cue in validity order (features are listed in
    descending validity: 0.95, 0.85, 0.75, 0.65, 0.55) and (b) the option
    favoured by the unit-weight tally of feature-wise wins.  We keep only
    trials where these two disagree in direction OR where the tally is tied
    (so a counting rule must guess).  The metric is the proportion of such
    trials on which the subject picked the option favoured by the first
    discriminating cue.
    """
    hits = []
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = min(a.shape[0], b.shape[0])
        a = a[:n]
        b = b[:n]

        # first discriminating cue (features already in descending validity)
        first_winner = None
        for j in range(n):
            if a[j] > b[j]:
                first_winner = 0
                break
            if b[j] > a[j]:
                first_winner = 1
                break
        if first_winner is None:
            continue  # no cue discriminates: uninformative trial

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = None  # counting rule must guess

        if tally_winner is not None and tally_winner == first_winner:
            continue  # agreement control trial: not diagnostic

        try:
            r = int(resp)
        except (TypeError, ValueError):
            continue
        hits.append(1.0 if r == first_winner else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.2820 (var=0.0035)
**Candidate trajectory (this loop):**
  - iter 1: 0.2943 (var=0.0017) (Δ vs real +0.0123)
  - iter 2: 0.2785 (var=0.0030) (Δ vs real -0.0035)
  - iter 3: 0.2515 (var=0.0020) (Δ vs real -0.0305)
  - iter 4: 0.2505 (var=0.0017) (Δ vs real -0.0315)
  - iter 5 (current): 0.2542 (var=0.0029) (Δ vs real -0.0277)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8515 (var=0.0078)
- pi_2: 0.1903 (var=0.0042)
- pi_3: 0.2870 (var=0.0019)
- pi_4: 0.2843 (var=0.0034)
- pi_5: 0.2722 (var=0.0027)
- pi_6: 0.2560 (var=0.0021)
- pi_7: 0.2878 (var=0.0023)
- pi_8: 0.2730 (var=0.0019)
- pi_9: 0.3068 (var=0.0031)
- pi_10: 0.2522 (var=0.0026)

### Experiment 2
**Design**
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.6, 0.93, 0.55, 0.87, 0.7, 0.78], dtype=float)

    def analyze(row):
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        n = min(a.shape[0], b.shape[0])
        a = a[:n]
        b = b[:n]
        val = validities[:n] if validities.shape[0] >= n else np.arange(n, 0, -1, dtype=float)
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        margin = a_wins - b_wins
        if margin > 0:
            tally_winner = 0
        elif margin < 0:
            tally_winner = 1
        else:
            tally_winner = -1
        order = np.argsort(-val, kind='stable')
        ttb_winner = -1
        for j in order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        return margin, tally_winner, ttb_winner

    info = [analyze(r) for _, r in data.iterrows()]
    margins = np.array([x[0] for x in info], dtype=float)
    tally_w = np.array([x[1] for x in info], dtype=int)
    ttb_w = np.array([x[2] for x in info], dtype=int)
    resp = data['response'].to_numpy().astype(int)

    # Group 1: tally-tie trials where TTB is decisive (parameter-free for Tallying)
    tie_mask = (tally_w == -1) & (ttb_w >= 0)
    # Group 2: trials where tally margin is >= 2 AND TTB points the other way
    dis_mask = (np.abs(margins) >= 2) & (tally_w >= 0) & (ttb_w >= 0) & (tally_w != ttb_w)

    if tie_mask.sum() == 0 and dis_mask.sum() == 0:
        return float('nan')

    if dis_mask.sum() > 0:
        p_tally = float(np.mean(resp[dis_mask] == tally_w[dis_mask]))
    else:
        p_tally = 0.5
    if tie_mask.sum() > 0:
        p_ttb_tie = float(np.mean(resp[tie_mask] == ttb_w[tie_mask]))
    else:
        p_ttb_tie = 0.5

    return p_tally - p_ttb_tie

```

**Observed (real) value:** 0.1744 (var=0.0127)
**Candidate trajectory (this loop):**
  - iter 1: 0.1822 (var=0.0079) (Δ vs real +0.0078)
  - iter 2: 0.2031 (var=0.0098) (Δ vs real +0.0286)
  - iter 3: 0.2022 (var=0.0156) (Δ vs real +0.0278)
  - iter 4: 0.1997 (var=0.0092) (Δ vs real +0.0253)
  - iter 5 (current): 0.2058 (var=0.0123) (Δ vs real +0.0314)
**Other theories' values on this metric (for reference):**
- pi_2: 0.3828 (var=0.0220)
- pi_1: -0.7044 (var=0.0395)
- pi_3: 0.1722 (var=0.0132)
- pi_4: 0.1856 (var=0.0146)
- pi_5: 0.1956 (var=0.0184)
- pi_6: 0.1639 (var=0.0160)
- pi_7: 0.2300 (var=0.0149)
- pi_8: 0.2117 (var=0.0142)
- pi_9: 0.3256 (var=0.0184)
- pi_10: 0.3175 (var=0.0088)

### Experiment 3
**Design**
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V = np.array([0.68, 0.96, 0.52, 0.88, 0.58, 0.78], dtype=float)

    hits = 0.0
    n = 0.0
    for _, row in data.iterrows():
        try:
            a = np.asarray([float(x) for x in row['option_a_ratings']], dtype=float)
            b = np.asarray([float(x) for x in row['option_b_ratings']], dtype=float)
        except Exception:
            continue
        k = int(min(a.shape[0], b.shape[0]))
        if k == 0:
            continue
        a = a[:k]
        b = b[:k]
        if V.shape[0] >= k:
            v = V[:k]
        else:
            v = np.concatenate([V, np.full(k - V.shape[0], 0.55)])[:k]

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        # keep only unit-tally TIES with at least one discriminating cue
        if a_wins != b_wins or a_wins == 0:
            continue

        w = v ** 2.0
        d = float(np.sum(w * (a - b)))
        # discard tie trials whose validity-weighted margin is itself
        # near zero (no clear "higher-validity side" to predict)
        if abs(d) < 0.15:
            continue

        resp = row['response']
        try:
            resp = int(resp)
        except Exception:
            continue
        if resp not in (0, 1):
            continue

        chose_a = (resp == 0)
        picked_high_validity = chose_a if d > 0 else (not chose_a)
        hits += 1.0 if picked_high_validity else 0.0
        n += 1.0

    if n == 0:
        return 0.5
    return float(hits / n)
```

**Observed (real) value:** 0.2856 (var=0.0160)
**Candidate trajectory (this loop):**
  - iter 1: 0.2433 (var=0.0030) (Δ vs real -0.0422)
  - iter 2: 0.2344 (var=0.0051) (Δ vs real -0.0511)
  - iter 3: 0.2494 (var=0.0038) (Δ vs real -0.0361)
  - iter 4: 0.2233 (var=0.0049) (Δ vs real -0.0622)
  - iter 5 (current): 0.2656 (var=0.0056) (Δ vs real -0.0200)
**Other theories' values on this metric (for reference):**
- pi_3: 0.9389 (var=0.0016)
- pi_2: 0.5100 (var=0.0066)
- pi_1: 0.8522 (var=0.0137)
- pi_4: 0.3056 (var=0.0052)
- pi_5: 0.2767 (var=0.0068)
- pi_6: 0.2928 (var=0.0057)
- pi_7: 0.2778 (var=0.0058)
- pi_8: 0.2794 (var=0.0061)
- pi_9: 0.2956 (var=0.0037)
- pi_10: 0.2650 (var=0.0064)

### Experiment 4
**Design**
  A=[1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    v = np.array([0.58, 0.97, 0.53, 0.80, 0.66, 0.90], dtype=float)
    w = v ** 2.0  # AVAI-style amplified weights (gamma=2)

    num = 0.0
    den = 0.0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.shape[0], b.shape[0], w.shape[0]))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        ww = w[:n]
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins != b_wins:
            continue  # not a tally tie
        d = float(np.sum(ww * (a - b)))
        if abs(d) < 0.30:
            continue  # tie trials whose weighted margin is negligible
        den += 1.0
        if d > 0:
            num += 1.0 if int(resp) == 0 else 0.0
        else:
            num += 1.0 if int(resp) == 1 else 0.0

    if den == 0:
        return 0.5
    return num / den
```

**Observed (real) value:** 0.1500 (var=0.0194)
**Candidate trajectory (this loop):**
  - iter 1: 0.1233 (var=0.0092) (Δ vs real -0.0267)
  - iter 2: 0.1250 (var=0.0090) (Δ vs real -0.0250)
  - iter 3: 0.1533 (var=0.0109) (Δ vs real +0.0033)
  - iter 4: 0.1267 (var=0.0109) (Δ vs real -0.0233)
  - iter 5 (current): 0.1317 (var=0.0084) (Δ vs real -0.0183)
**Other theories' values on this metric (for reference):**
- pi_2: 0.4917 (var=0.0165)
- pi_3: 0.9850 (var=0.0010)
- pi_1: 0.8500 (var=0.0219)
- pi_4: 0.1583 (var=0.0128)
- pi_5: 0.1650 (var=0.0115)
- pi_6: 0.1450 (var=0.0086)
- pi_7: 0.1500 (var=0.0133)
- pi_8: 0.1217 (var=0.0081)
- pi_9: 0.1067 (var=0.0070)
- pi_10: 0.1600 (var=0.0080)

### Experiment 5
**Design**
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 1]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    correct = []
    for _, row in data.iterrows():
        try:
            a = np.asarray(list(row['option_a_ratings']), dtype=float).ravel()
            b = np.asarray(list(row['option_b_ratings']), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        d = a[:n] - b[:n]
        nz = d[d != 0.0]
        if nz.size == 0:
            continue
        # dominance trial: every discriminating cue favours the same option
        if not (np.all(nz > 0) or np.all(nz < 0)):
            continue
        dominant_is_a = bool(np.all(nz > 0))
        try:
            resp = int(row['response'])
        except Exception:
            continue
        chose_a = (resp == 0)
        correct.append(1.0 if (chose_a == dominant_is_a) else 0.0)

    if len(correct) == 0:
        return 0.5
    return float(np.mean(correct))
```

**Observed (real) value:** 0.7427 (var=0.0173)
**Candidate trajectory (this loop):**
  - iter 1: 0.7653 (var=0.0048) (Δ vs real +0.0227)
  - iter 2: 0.7527 (var=0.0051) (Δ vs real +0.0100)
  - iter 3: 0.7673 (var=0.0063) (Δ vs real +0.0247)
  - iter 4: 0.7467 (var=0.0057) (Δ vs real +0.0040)
  - iter 5 (current): 0.7693 (var=0.0056) (Δ vs real +0.0267)
**Other theories' values on this metric (for reference):**
- pi_3: 0.9847 (var=0.0005)
- pi_4: 0.7440 (var=0.0064)
- pi_1: 0.8340 (var=0.0138)
- pi_2: 0.8493 (var=0.0126)
- pi_5: 0.7427 (var=0.0074)
- pi_6: 0.7773 (var=0.0049)
- pi_7: 0.7467 (var=0.0048)
- pi_8: 0.7487 (var=0.0072)
- pi_9: 0.7473 (var=0.0050)
- pi_10: 0.7707 (var=0.0058)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    # design validities (fixed by the experimental design)
    v_design = np.array([0.95, 0.70, 0.55, 0.95, 0.70, 0.55], dtype=float)
    hits = 0
    n = 0
    for a_raw, b_raw, r in zip(data['option_a_ratings'],
                               data['option_b_ratings'],
                               data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        k = int(min(a.size, b.size))
        if k == 0:
            continue
        if v_design.size >= k:
            vv = v_design[:k]
        else:
            vv = np.linspace(0.95, 0.55, k)
        d = a[:k] - b[:k]
        idx = np.nonzero(d != 0.0)[0]
        if idx.size != 2:
            continue
        j1 = int(idx[0])
        j2 = int(idx[1])
        # the two discriminating cues must point to OPPOSITE options
        if d[j1] * d[j2] > 0:
            continue
        # and the LATER cue must be the LESS valid one
        if not (vv[j2] < vv[j1]):
            continue
        late_choice = 0 if d[j2] > 0 else 1  # 0 = A, 1 = B
        try:
            resp = int(r)
        except Exception:
            continue
        n += 1
        if resp == late_choice:
            hits += 1
    if n == 0:
        return float('nan')
    return float(hits) / float(n)
```

**Observed (real) value:** 0.5067 (var=0.0112)
**Candidate trajectory (this loop):**
  - iter 1: 0.5200 (var=0.0097) (Δ vs real +0.0133)
  - iter 2: 0.4925 (var=0.0110) (Δ vs real -0.0142)
  - iter 3: 0.5050 (var=0.0120) (Δ vs real -0.0017)
  - iter 4: 0.4767 (var=0.0132) (Δ vs real -0.0300)
  - iter 5 (current): 0.5242 (var=0.0076) (Δ vs real +0.0175)
**Other theories' values on this metric (for reference):**
- pi_4: 0.8367 (var=0.0052)
- pi_3: 0.0300 (var=0.0018)
- pi_1: 0.1550 (var=0.0169)
- pi_2: 0.4942 (var=0.0103)
- pi_5: 0.5083 (var=0.0072)
- pi_6: 0.5033 (var=0.0076)
- pi_7: 0.4817 (var=0.0130)
- pi_8: 0.4725 (var=0.0109)
- pi_9: 0.5208 (var=0.0068)
- pi_10: 0.5017 (var=0.0113)

### Experiment 7
**Design**
  A=[1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = []
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float).ravel()
        b = np.asarray(row['option_b_ratings'], dtype=float).ravel()
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        d = a[:n] - b[:n]
        disc = np.nonzero(d != 0.0)[0]
        m = int(disc.size)
        if m < 2:
            continue
        fav_a = d[disc] > 0.0
        # skip unanimous (dominance) displays: both theories agree there
        if fav_a.all() or (~fav_a).all():
            continue
        # option favoured by the LAST-READ (highest-index) discriminating row
        last_idx = disc[-1]
        late_option = 0 if d[last_idx] > 0.0 else 1
        try:
            resp = int(row['response'])
        except Exception:
            continue
        hits.append(1.0 if resp == late_option else 0.0)

    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.4383 (var=0.0023)
**Candidate trajectory (this loop):**
  - iter 1: 0.4478 (var=0.0037) (Δ vs real +0.0094)
  - iter 2: 0.4589 (var=0.0026) (Δ vs real +0.0206)
  - iter 3: 0.4414 (var=0.0030) (Δ vs real +0.0031)
  - iter 4: 0.4542 (var=0.0030) (Δ vs real +0.0158)
  - iter 5 (current): 0.4617 (var=0.0042) (Δ vs real +0.0233)
**Other theories' values on this metric (for reference):**
- pi_5: 0.4711 (var=0.0034)
- pi_4: 0.7642 (var=0.0020)
- pi_1: 0.2703 (var=0.0046)
- pi_2: 0.3842 (var=0.0037)
- pi_3: 0.3467 (var=0.0009)
- pi_6: 0.4419 (var=0.0028)
- pi_7: 0.4508 (var=0.0038)
- pi_8: 0.4408 (var=0.0032)
- pi_9: 0.4628 (var=0.0033)
- pi_10: 0.4500 (var=0.0038)

### Experiment 8
**Design**
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Design validities (fixed by the experiment); fallback handles other lengths.
    V_DESIGN = np.array([0.955, 0.545, 0.950, 0.540, 0.945, 0.535], dtype=float)
    LAM = 1.6
    DELTA = 0.9

    hits = []
    for _, row in data.iterrows():
        try:
            a = np.asarray(list(row['option_a_ratings']), dtype=float).ravel()
            b = np.asarray(list(row['option_b_ratings']), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]

        if V_DESIGN.size >= n:
            v = V_DESIGN[:n]
        else:
            v = np.concatenate([V_DESIGN, np.full(n - V_DESIGN.size, 0.545)])[:n]

        d = a - b
        disc = np.nonzero(d != 0.0)[0]
        m = int(disc.size)
        if m < 2:
            continue

        # salience of each discriminating row: recency x (1 - validity)
        j = disc.astype(float)
        logu = LAM * j + DELTA * np.log(np.clip(1.0 - v[disc], 1e-9, None))
        logu = logu - np.max(logu)
        u = np.exp(logu)
        top = disc[int(np.argmax(u))]
        top_owner_a = bool(d[top] > 0.0)  # True -> the salient row favours A

        n_a = int(np.sum(d[disc] > 0.0))
        n_b = m - n_a

        # include only trials where the row-count tally does NOT strictly
        # agree with the most salient (late / low-validity) discriminating row
        if n_a > n_b:
            majority_a = True
            tie = False
        elif n_b > n_a:
            majority_a = False
            tie = False
        else:
            majority_a = None
            tie = True
        if (not tie) and (majority_a == top_owner_a):
            continue

        try:
            resp = int(row['response'])
        except Exception:
            continue
        chose_a = (resp == 0)
        hits.append(1.0 if (chose_a == top_owner_a) else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.7697 (var=0.0057)
**Candidate trajectory (this loop):**
  - iter 1: 0.8231 (var=0.0023) (Δ vs real +0.0534)
  - iter 2: 0.8100 (var=0.0031) (Δ vs real +0.0403)
  - iter 3: 0.8163 (var=0.0018) (Δ vs real +0.0466)
  - iter 4: 0.8063 (var=0.0031) (Δ vs real +0.0366)
  - iter 5 (current): 0.8134 (var=0.0022) (Δ vs real +0.0437)
**Other theories' values on this metric (for reference):**
- pi_4: 0.7326 (var=0.0025)
- pi_5: 0.4900 (var=0.0045)
- pi_1: 0.1511 (var=0.0123)
- pi_2: 0.3354 (var=0.0031)
- pi_3: 0.0803 (var=0.0009)
- pi_6: 0.7540 (var=0.0026)
- pi_7: 0.7686 (var=0.0034)
- pi_8: 0.7611 (var=0.0025)
- pi_9: 0.7766 (var=0.0030)
- pi_10: 0.7960 (var=0.0025)

### Experiment 9
**Design**
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V_DESIGN = np.array([0.958, 0.546, 0.954, 0.542, 0.950, 0.538], dtype=float)
    LAM = 1.5      # reading-order recency gain (shared by both accounts)
    GAM = 0.9      # oddness exponent on (1 - validity) (shared by both accounts)

    hits = 0.0
    tot = 0.0

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_raw, dtype=float).ravel()
            b = np.asarray(b_raw, dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]

        if n == V_DESIGN.size:
            v = V_DESIGN.copy()
        else:
            v = np.linspace(0.95, 0.55, n)
        v = np.clip(v, 0.5, 0.995)

        diff = a - b
        disc = np.nonzero(diff != 0.0)[0]
        m = int(disc.size)
        if m < 2:
            continue
        signs = np.sign(diff[disc])
        # keep only CONFLICT displays (both options win at least one row)
        if np.all(signs > 0) or np.all(signs < 0):
            continue

        logw = GAM * np.log(np.clip(1.0 - v[disc], 1e-9, None)) + LAM * disc.astype(float)
        k = int(np.argmax(logw))
        favored_a = signs[k] > 0.0

        try:
            r = int(resp)
        except Exception:
            continue
        chose_a = (r == 0)
        hits += 1.0 if (chose_a == favored_a) else 0.0
        tot += 1.0

    if tot == 0.0:
        return float('nan')
    return float(hits / tot)
```

**Observed (real) value:** 0.8189 (var=0.0074)
**Candidate trajectory (this loop):**
  - iter 1: 0.8278 (var=0.0021) (Δ vs real +0.0089)
  - iter 2: 0.8314 (var=0.0019) (Δ vs real +0.0125)
  - iter 3: 0.8128 (var=0.0018) (Δ vs real -0.0061)
  - iter 4: 0.8078 (var=0.0020) (Δ vs real -0.0111)
  - iter 5 (current): 0.8061 (var=0.0028) (Δ vs real -0.0128)
**Other theories' values on this metric (for reference):**
- pi_5: 0.4964 (var=0.0034)
- pi_6: 0.7364 (var=0.0031)
- pi_1: 0.1528 (var=0.0126)
- pi_2: 0.3228 (var=0.0037)
- pi_3: 0.0178 (var=0.0002)
- pi_4: 0.7092 (var=0.0034)
- pi_7: 0.7714 (var=0.0022)
- pi_8: 0.7536 (var=0.0025)
- pi_9: 0.7783 (var=0.0025)
- pi_10: 0.7953 (var=0.0023)

### Experiment 10
**Design**
  A=[1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    # Design validities (fixed by the experiment)
    v_default = np.array([0.53, 0.72, 0.86, 0.93, 0.99], dtype=float)

    def weights(n):
        if n <= v_default.size:
            v = v_default[:n]
        else:
            v = np.concatenate([v_default, np.full(n - v_default.size, 0.99)])
        v = np.clip(v, 0.5, 0.9995)
        logw = 0.9 * np.log(1.0 - v) + 1.5 * np.arange(n, dtype=float)
        logw = logw - np.max(logw)
        return np.exp(logw)

    wcache = {}
    hits = []
    for a_raw, b_raw, resp in zip(data['option_a_ratings'].values,
                                  data['option_b_ratings'].values,
                                  data['response'].values):
        try:
            a = np.asarray(list(a_raw), dtype=float).ravel()
            b = np.asarray(list(b_raw), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        d = a - b
        nA = int(np.sum(d > 0))
        nB = int(np.sum(d < 0))
        # keep only CONFLICT displays (both options favoured by at least one expert)
        if nA == 0 or nB == 0:
            continue
        if n not in wcache:
            wcache[n] = weights(n)
        w = wcache[n]
        S = float(np.sum(np.sign(d) * w))
        if S == 0.0:
            continue
        fav = 0 if S > 0 else 1  # response coding: 0 = A, 1 = B
        try:
            r = int(resp)
        except Exception:
            continue
        hits.append(1.0 if r == fav else 0.0)

    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.4178 (var=0.0051)
**Candidate trajectory (this loop):**
  - iter 1: 0.4142 (var=0.0030) (Δ vs real -0.0036)
  - iter 2: 0.4153 (var=0.0028) (Δ vs real -0.0025)
  - iter 3: 0.4039 (var=0.0034) (Δ vs real -0.0139)
  - iter 4: 0.4067 (var=0.0021) (Δ vs real -0.0111)
  - iter 5 (current): 0.4200 (var=0.0021) (Δ vs real +0.0022)
**Other theories' values on this metric (for reference):**
- pi_6: 0.7386 (var=0.0031)
- pi_5: 0.6297 (var=0.0048)
- pi_1: 0.6053 (var=0.0037)
- pi_2: 0.5439 (var=0.0033)
- pi_3: 0.7967 (var=0.0021)
- pi_4: 0.6303 (var=0.0046)
- pi_7: 0.3878 (var=0.0029)
- pi_8: 0.4492 (var=0.0019)
- pi_9: 0.4247 (var=0.0030)
- pi_10: 0.4236 (var=0.0018)

### Experiment 11
**Design**
  A=[1, 1, 0, 1, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Design-fixed printed validities for this experiment
    v = np.array([0.55, 0.90, 0.75, 0.95, 0.68, 0.85], dtype=float)
    n = v.size
    j = np.arange(n, dtype=float)

    # MDSC-NV salience: near-argmax doubt rule (delta=15, lam=0.115*15)
    logu = 15.0 * np.log(np.clip(1.0 - v, 1e-12, None)) + 1.725 * j
    # SSI-DS+ compensatory summation weights (gamma=0.9, lam=1.5)
    w_ssi = np.power(np.clip(1.0 - v, 1e-12, None), 0.9) * np.exp(1.5 * j)

    hits = 0
    tot = 0
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_raw, dtype=float).ravel()
            b = np.asarray(b_raw, dtype=float).ravel()
        except Exception:
            continue
        if a.size != n or b.size != n:
            continue
        d = a - b
        disc = np.nonzero(d != 0.0)[0]
        if disc.size == 0:
            continue

        # MDSC-NV predicted winner: verdict of the single most doubtful
        # discriminating expert
        k = disc[int(np.argmax(logu[disc]))]
        pred_mdsc = 0 if d[k] > 0 else 1

        # SSI-DS+ predicted winner: sign of the weighted sum over all
        # discriminating rows (coalitions add, late rows dominate)
        E = float(np.sum(np.sign(d[disc]) * w_ssi[disc]))
        if E == 0.0:
            continue
        pred_ssi = 0 if E > 0 else 1

        if pred_ssi == pred_mdsc:
            continue  # non-diagnostic trial type

        tot += 1
        try:
            resp = int(r)
        except Exception:
            continue
        if resp == pred_mdsc:
            hits += 1

    if tot == 0:
        return 0.5
    return float(hits) / float(tot)
```

**Observed (real) value:** 0.5925 (var=0.0026)
**Candidate trajectory (this loop):**
  - iter 1: 0.6083 (var=0.0031) (Δ vs real +0.0158)
  - iter 2: 0.6117 (var=0.0027) (Δ vs real +0.0192)
  - iter 3: 0.5933 (var=0.0034) (Δ vs real +0.0008)
  - iter 4: 0.6058 (var=0.0027) (Δ vs real +0.0133)
  - iter 5 (current): 0.6075 (var=0.0036) (Δ vs real +0.0150)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6833 (var=0.0038)
- pi_6: 0.2583 (var=0.0034)
- pi_1: 0.1550 (var=0.0102)
- pi_2: 0.4058 (var=0.0050)
- pi_3: 0.1054 (var=0.0016)
- pi_4: 0.3046 (var=0.0036)
- pi_5: 0.2854 (var=0.0033)
- pi_8: 0.6367 (var=0.0043)
- pi_9: 0.6033 (var=0.0045)
- pi_10: 0.5946 (var=0.0036)

### Experiment 12
**Design**
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V_DESIGN = np.array([0.51, 0.72, 0.80, 0.90, 0.95, 0.985], dtype=float)

    GAMMA = 0.90
    LAM = 1.50
    DELTA = 15.0
    LAM_M = 1.725

    hits = 0.0
    tot = 0.0

    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        try:
            a = np.asarray(list(a_raw), dtype=float).ravel()
            b = np.asarray(list(b_raw), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]

        if n <= V_DESIGN.size:
            v = V_DESIGN[:n]
        else:
            v = np.concatenate([V_DESIGN, np.full(n - V_DESIGN.size, 0.985)])
        v = np.clip(v, 0.5, 0.9995)

        diff = a - b
        disc = np.nonzero(diff != 0.0)[0]
        if disc.size == 0:
            continue
        signs = np.sign(diff[disc])

        # --- SSI-DS+ side: max-normalised weighted SUM, late/high-validity dominated
        logw = GAMMA * np.log(np.clip(1.0 - v[disc], 1e-12, None)) + LAM * disc.astype(float)
        logw = logw - np.max(logw)
        w = np.exp(logw)
        E = float(np.sum(signs * w))
        if abs(E) < 1e-9:
            continue
        ssi_side = 1.0 if E > 0 else -1.0

        # --- MDSC-NV side: single most-doubtful DISCRIMINATING row decides
        sal = DELTA * np.log(np.clip(1.0 - v[disc], 1e-12, None)) + LAM_M * disc.astype(float)
        k = int(np.argmax(sal))
        mdsc_side = float(signs[k])
        if mdsc_side == 0.0:
            continue

        # keep only trials where the two accounts point to OPPOSITE options
        if mdsc_side == ssi_side:
            continue

        try:
            r = int(resp)
        except Exception:
            continue
        chose_a = (r == 0)
        ssi_favours_a = (ssi_side > 0)
        hits += 1.0 if (chose_a == ssi_favours_a) else 0.0
        tot += 1.0

    if tot == 0.0:
        return 0.5
    return float(hits / tot)
```

**Observed (real) value:** 0.2608 (var=0.0079)
**Candidate trajectory (this loop):**
  - iter 1: 0.1821 (var=0.0030) (Δ vs real -0.0787)
  - iter 2: 0.2183 (var=0.0051) (Δ vs real -0.0425)
  - iter 3: 0.2004 (var=0.0023) (Δ vs real -0.0604)
  - iter 4: 0.1983 (var=0.0035) (Δ vs real -0.0625)
  - iter 5 (current): 0.2062 (var=0.0029) (Δ vs real -0.0546)
**Other theories' values on this metric (for reference):**
- pi_6: 0.7412 (var=0.0040)
- pi_7: 0.2592 (var=0.0042)
- pi_1: 0.8400 (var=0.0123)
- pi_2: 0.5587 (var=0.0027)
- pi_3: 0.8158 (var=0.0005)
- pi_4: 0.7417 (var=0.0031)
- pi_5: 0.7421 (var=0.0057)
- pi_8: 0.2729 (var=0.0043)
- pi_9: 0.2617 (var=0.0055)
- pi_10: 0.2013 (var=0.0047)

### Experiment 13
**Design**
  A=[1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 1]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = []
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.size, b.size))
        if n < 5:
            continue
        a = a[:n]
        b = b[:n]
        d = a - b
        disc = [int(i) for i in np.nonzero(d != 0.0)[0]]
        # require feature 0 (validity .68) to discriminate
        if 0 not in disc:
            continue
        # require the global doubt anchor, feature 3 (validity .52), to be SILENT
        if 3 in disc:
            continue
        fav_a = [i for i in disc if d[i] > 0.0]
        fav_b = [i for i in disc if d[i] < 0.0]
        if d[0] > 0.0:
            lone, other = fav_a, fav_b
            lone_is_a = True
        else:
            lone, other = fav_b, fav_a
            lone_is_a = False
        # exactly one dissenter (feature 0) against a coalition of >=2 more valid experts
        if len(lone) != 1 or len(other) < 2:
            continue
        try:
            resp = int(r)
        except Exception:
            continue
        chose_lone = (resp == 0) if lone_is_a else (resp == 1)
        hits.append(1.0 if chose_lone else 0.0)
    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.5460 (var=0.0126)
**Candidate trajectory (this loop):**
  - iter 1: 0.4570 (var=0.0133) (Δ vs real -0.0890)
  - iter 2: 0.4530 (var=0.0101) (Δ vs real -0.0930)
  - iter 3: 0.4500 (var=0.0146) (Δ vs real -0.0960)
  - iter 4: 0.4790 (var=0.0153) (Δ vs real -0.0670)
  - iter 5 (current): 0.5210 (var=0.0070) (Δ vs real -0.0250)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6410 (var=0.0093)
- pi_8: 0.2680 (var=0.0082)
- pi_1: 0.1620 (var=0.0145)
- pi_2: 0.1700 (var=0.0205)
- pi_3: 0.0110 (var=0.0005)
- pi_4: 0.2580 (var=0.0097)
- pi_5: 0.2380 (var=0.0124)
- pi_6: 0.2580 (var=0.0074)
- pi_9: 0.4660 (var=0.0150)
- pi_10: 0.5080 (var=0.0118)

### Experiment 14
**Design**
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    V = np.array([0.62, 0.78, 0.86, 0.93, 0.53, 0.97], dtype=float)
    ANCHOR = 4  # the .53 expert (below DTV's doubt trigger)
    hits = 0.0
    tot = 0.0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'].tolist(),
                                  data['option_b_ratings'].tolist(),
                                  data['response'].tolist()):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.size, b.size))
        if n != 6:
            continue
        diff = a[:6] - b[:6]
        disc = np.nonzero(diff != 0.0)[0]
        m = int(disc.size)
        if m < 3:
            continue
        # the globally most doubtful expert (.53) must be SILENT
        if ANCHOR in set(disc.tolist()):
            continue
        d = diff[disc]
        na = int(np.sum(d > 0.0))
        nb = m - na
        if min(na, nb) != 1 or max(na, nb) < 2:
            continue
        if na == 1:
            lone = int(disc[d > 0.0][0])
            fav = 0  # option A favoured by the lone dissenter
        else:
            lone = int(disc[d < 0.0][0])
            fav = 1
        # the lone dissenter must be the LEAST valid discriminating expert
        if abs(V[lone] - float(np.min(V[disc]))) > 1e-9:
            continue
        tot += 1.0
        if int(resp) == fav:
            hits += 1.0
    if tot < 1.0:
        return 0.5
    return float(hits / tot)
```

**Observed (real) value:** 0.4675 (var=0.0144)
**Candidate trajectory (this loop):**
  - iter 1: 0.5150 (var=0.0170) (Δ vs real +0.0475)
  - iter 2: 0.5363 (var=0.0167) (Δ vs real +0.0687)
  - iter 3: 0.5162 (var=0.0190) (Δ vs real +0.0487)
  - iter 4: 0.5050 (var=0.0153) (Δ vs real +0.0375)
  - iter 5 (current): 0.5062 (var=0.0161) (Δ vs real +0.0387)
**Other theories' values on this metric (for reference):**
- pi_8: 0.2313 (var=0.0086)
- pi_7: 0.6388 (var=0.0149)
- pi_1: 0.1550 (var=0.0197)
- pi_2: 0.1313 (var=0.0107)
- pi_3: 0.0238 (var=0.0015)
- pi_4: 0.2812 (var=0.0111)
- pi_5: 0.2863 (var=0.0094)
- pi_6: 0.2313 (var=0.0138)
- pi_9: 0.5387 (var=0.0195)
- pi_10: 0.5413 (var=0.0121)

### Experiment 15
**Design**
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = 0.0
    tot = 0.0
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()
    ANCHOR = 3  # column with the lowest printed validity (0.55)
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        a = [int(x) for x in list(a_raw)]
        b = [int(x) for x in list(b_raw)]
        k = min(len(a), len(b))
        if k <= ANCHOR:
            continue
        if a[ANCHOR] == b[ANCHOR]:
            continue  # anchor silent -> not a coalition test
        n_a = 0
        n_b = 0
        for i in range(k):
            if a[i] > b[i]:
                n_a += 1
            elif b[i] > a[i]:
                n_b += 1
        anchor_favors_a = a[ANCHOR] > b[ANCHOR]
        opposing = n_b if anchor_favors_a else n_a
        if opposing < 1:
            continue  # pure dominance for the anchor side -> no coalition
        try:
            resp = int(r)
        except Exception:
            continue
        chose_a = (resp == 0)
        if chose_a == anchor_favors_a:
            hits += 1.0
        tot += 1.0
    if tot == 0.0:
        return float('nan')
    return float(hits / tot)
```

**Observed (real) value:** 0.8620 (var=0.0155)
**Candidate trajectory (this loop):**
  - iter 1: 0.7070 (var=0.0034) (Δ vs real -0.1550)
  - iter 2: 0.7497 (var=0.0038) (Δ vs real -0.1123)
  - iter 3: 0.7803 (var=0.0029) (Δ vs real -0.0817)
  - iter 4: 0.8067 (var=0.0038) (Δ vs real -0.0553)
  - iter 5 (current): 0.8043 (var=0.0021) (Δ vs real -0.0577)
**Other theories' values on this metric (for reference):**
- pi_7: 0.7610 (var=0.0035)
- pi_9: 0.4777 (var=0.0043)
- pi_1: 0.3003 (var=0.0058)
- pi_2: 0.2920 (var=0.0039)
- pi_3: 0.1703 (var=0.0013)
- pi_4: 0.2870 (var=0.0043)
- pi_5: 0.2827 (var=0.0026)
- pi_6: 0.2450 (var=0.0025)
- pi_8: 0.7143 (var=0.0022)
- pi_10: 0.8087 (var=0.0029)

### Experiment 16
**Design**
  A=[1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = 0.0
    n = 0.0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(list(a_raw), dtype=float).ravel()
        b = np.asarray(list(b_raw), dtype=float).ravel()
        k = int(min(a.size, b.size))
        if k < 6:
            continue
        # the near-chance anchor expert (column 0, validity .52) must discriminate
        if a[0] == b[0]:
            continue
        anchor_side = 0 if a[0] > b[0] else 1  # 0 == option A, 1 == option B
        # count late, mid-doubt rows (columns 3,4,5) that oppose the anchor
        opp = 0
        for j in (3, 4, 5):
            if a[j] == b[j]:
                continue
            fav = 0 if a[j] > b[j] else 1
            if fav != anchor_side:
                opp += 1
        if opp < 2:
            continue
        n += 1.0
        try:
            r = int(resp)
        except Exception:
            continue
        if r == anchor_side:
            hits += 1.0

    if n == 0.0:
        return 0.5
    return float(hits / n)

```

**Observed (real) value:** 0.8260 (var=0.0180)
**Candidate trajectory (this loop):**
  - iter 1: 0.8395 (var=0.0031) (Δ vs real +0.0135)
  - iter 2: 0.8225 (var=0.0035) (Δ vs real -0.0035)
  - iter 3: 0.8495 (var=0.0025) (Δ vs real +0.0235)
  - iter 4: 0.8605 (var=0.0028) (Δ vs real +0.0345)
  - iter 5 (current): 0.8440 (var=0.0024) (Δ vs real +0.0180)
**Other theories' values on this metric (for reference):**
- pi_9: 0.4215 (var=0.0085)
- pi_7: 0.7245 (var=0.0054)
- pi_1: 0.4340 (var=0.0037)
- pi_2: 0.2900 (var=0.0065)
- pi_3: 0.1700 (var=0.0026)
- pi_4: 0.3045 (var=0.0052)
- pi_5: 0.3325 (var=0.0058)
- pi_6: 0.3115 (var=0.0039)
- pi_8: 0.6770 (var=0.0061)
- pi_10: 0.8075 (var=0.0040)

### Experiment 17
**Design**
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = 0.0
    tot = 0.0
    for a_raw, b_raw, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        try:
            a = [int(x) for x in a_raw]
            b = [int(x) for x in b_raw]
        except Exception:
            continue
        if len(a) < 6 or len(b) < 6:
            continue
        # expert 4 (validity .52, the near-chance 'anchor') must be SILENT
        if a[4] != b[4]:
            continue
        # expert 5 (validity .66, mid-doubt) must discriminate
        d5 = a[5] - b[5]
        if d5 == 0:
            continue
        # there must be a genuine opposing coalition among the more valid experts 0..3
        opposed = False
        for j in range(4):
            dj = a[j] - b[j]
            if dj != 0 and (dj * d5) < 0:
                opposed = True
                break
        if not opposed:
            continue
        fav = 0 if d5 > 0 else 1  # option favoured by the .66 expert
        tot += 1.0
        try:
            rr = int(r)
        except Exception:
            continue
        if rr == fav:
            hits += 1.0
    if tot <= 0:
        return 0.5
    return float(hits / tot)
```

**Observed (real) value:** 0.4925 (var=0.0074)
**Candidate trajectory (this loop):**
  - iter 1: 0.5206 (var=0.0060) (Δ vs real +0.0281)
  - iter 2: 0.5606 (var=0.0065) (Δ vs real +0.0681)
  - iter 3: 0.4913 (var=0.0087) (Δ vs real -0.0012)
  - iter 4: 0.4944 (var=0.0068) (Δ vs real +0.0019)
  - iter 5 (current): 0.4894 (var=0.0075) (Δ vs real -0.0031)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6956 (var=0.0072)
- pi_10: 0.4906 (var=0.0058)
- pi_1: 0.4988 (var=0.0030)
- pi_2: 0.3175 (var=0.0067)
- pi_3: 0.3875 (var=0.0033)
- pi_4: 0.7712 (var=0.0079)
- pi_5: 0.7512 (var=0.0059)
- pi_6: 0.7525 (var=0.0064)
- pi_8: 0.3119 (var=0.0063)
- pi_9: 0.5931 (var=0.0080)

### Experiment 18
**Design**
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    ANCHOR = 4   # printed validity .52  (the only sub-.558 expert)
    SECOND = 5   # printed validity .68, last column (secondary doubt row)

    t_num = 0.0; t_den = 0.0   # anchor-follow rate on LONG, low-opposition displays
    c_num = 0.0; c_den = 0.0   # c5-follow rate when the .52 anchor is SILENT

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_, b_, r_ in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_, dtype=float).ravel()
            b = np.asarray(b_, dtype=float).ravel()
            r = int(r_)
        except Exception:
            continue
        if a.size < 6 or b.size < 6:
            continue
        d = a[:6] - b[:6]
        disc = np.nonzero(d != 0.0)[0]
        m = int(disc.size)
        if m == 0:
            continue
        nA = int(np.sum(d[disc] > 0.0))
        nB = m - nA
        kconf = min(nA, nB)
        chose_a = (r == 0)

        anchor_speaks = bool(np.any(disc == ANCHOR))
        second_speaks = bool(np.any(disc == SECOND))

        if anchor_speaks and m >= 4 and kconf <= 1:
            # long display, anchor either alone against a coalition or with everyone
            fav_a = (d[ANCHOR] > 0.0)
            t_den += 1.0
            if chose_a == fav_a:
                t_num += 1.0
        elif (not anchor_speaks) and second_speaks and kconf == 1:
            # anchor silent; is the .68 row the LONE dissenter on its side?
            fav_a_5 = (d[SECOND] > 0.0)
            side_count = nA if fav_a_5 else nB
            if side_count == 1:
                c_den += 1.0
                if chose_a == fav_a_5:
                    c_num += 1.0

    t_rate = (t_num / t_den) if t_den > 0 else 0.5
    c_rate = (c_num / c_den) if c_den > 0 else 0.5
    return float(t_rate - c_rate)
```

**Observed (real) value:** 0.3183 (var=0.0405)
**Candidate trajectory (this loop):**
  - iter 1: 0.1742 (var=0.0168) (Δ vs real -0.1442)
  - iter 2: 0.2500 (var=0.0173) (Δ vs real -0.0683)
  - iter 3: 0.2575 (var=0.0128) (Δ vs real -0.0608)
  - iter 4: 0.2975 (var=0.0160) (Δ vs real -0.0208)
  - iter 5 (current): 0.2842 (var=0.0213) (Δ vs real -0.0342)
**Other theories' values on this metric (for reference):**
- pi_10: 0.3550 (var=0.0214)
- pi_7: 0.0125 (var=0.0220)
- pi_1: -0.0267 (var=0.0062)
- pi_2: 0.1300 (var=0.0079)
- pi_3: 0.1117 (var=0.0039)
- pi_4: -0.2992 (var=0.0200)
- pi_5: -0.3408 (var=0.0161)
- pi_6: -0.3108 (var=0.0127)
- pi_8: 0.3800 (var=0.0208)
- pi_9: -0.0500 (var=0.0184)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1
Verdict: regenerate
Interpretation: SSG is a genuine improvement over both pi_7 and pi_10 on the pooled set: it nails Exp 1 (.294 vs .282), Exp 2's T
inus C term (.182 vs .174 
inus pi_10's biggest miss of .3175 is closed), Exp 4 (.123 vs .150), Exps 5/6/7 within ~.02, Exps 10/11 (.414/.608 vs .418/.593), Exp 14 (.515 vs .468) and Exp 17 (.521 vs .493). The oddness-share redefinition (share = \u03a3 g_j o_j / \u03a3 o_j) clearly does the work the arbiter asked for: co-scandalous displays (Exps 8/9) stay one-reason, and the .55 bystander dilution kills the Exp-2 over-prediction. Faithfulness to the prescribed RELATIVE-SHARE GATING family is good 
inus the gate is a graded sigmoid on a share quantity, the one-reason limb is degraded by opposition only (not display length), and the compensatory limb is divisively normalised as specified. The residual misses are concentrated in the adjudication limb's *level*, not its logic: Exp 15 is .707 vs .862 (under by .155) and Exp 18's T
inus C is .174 vs .318 (under by .144), both of which pi_10 fits better (.809 / .355); Exp 13 is .457 vs .546 (under by .09). Simultaneously the model slightly OVER-shoots the near-degenerate one-reason designs (Exp 8 .823 vs .770, Exp 9 .828 vs .819) and UNDER-shoots two anti-validity/compensatory metrics (Exp 12 .182 vs .261, Exp 3 .243 vs .286). Read together, these say: the total amount of one-reason fidelity is roughly right, but it is distributed wrongly across opposition-coalition sizes (too steep a rho_opp discount, which is exactly what depresses the .55/.52-anchor follow rates in Exps 15/18 where the anchor faces 2
inus3 opposing rows), and the compensatory limb is a touch too deterministic.
Rationale: The candidate was ACCEPTED (loss 0.0672, new running best), so the base is safe 
inus but two experiments are still off by ~.15 in a systematic, diagnosable direction, and the fix is a pure in-family re-calibration, not a redesign. Keep the SSG architecture exactly as written (oddness-share gate, log-sigmoid scandal, opposition-only degradation, divisively normalised integration, degeneracy fallback) and adjust three knobs:

1. FLATTEN the opposition discount. rho_opp is currently [0.83, 0.93]; against the 2
inus3-row coalitions in Exps 15/16/18 this compounds to ~.7
inus.86 and is the direct cause of Exp 15 = .707 (real .862) and the deflated T-term of Exp 18. The arbiter's point 3 explicitly asks for a nearly FLAT one-reason limb; push rho_opp to ~[0.93, 0.99] (or replace the geometric power by a saturating discount such as rho_opp^sqrt(k_conf-1)). Because Exps 8/9 are currently over-predicted by ~.05, pay for the extra flatness with a small compensating rise in eps_t (e.g. [0.24, 0.32]) rather than by shrinking it 
inus that keeps the mean one-reason fidelity where it already fits and only re-shapes its dependence on coalition size. Net expected effect: Exp 15 up ~.10, Exp 18 T up, Exps 8/9 down ~.03, Exp 17 roughly unchanged (the .66 row is not scandalous so the gate stays shut).

2. Slightly widen the gate for lone near-chance anchors. Exp 13 (.457 vs .546) and the Exp-18 T-term both involve a single low-validity dissenter that humans follow more often than SSG does. Lower c_share to ~[0.64, 0.72] and/or raise gate_floor to ~[0.34, 0.50], leaving w_share as is. Do NOT touch the g-weighted share definition 
inus it is what buys Exp 2 and Exp 4, the two places pi_10 fails.

3. Soften the integration limb marginally. Exps 12 (.182 vs .261) and 3 (.243 vs .286) are both under-shot in the anti-validity direction, i.e. the compensatory choice is too deterministic. Raise sigma to ~[0.55, 0.75] or drop beta to ~[1.8, 2.3]; do not change gamma_w/lam, which are currently delivering Exps 10/11/14 almost exactly.

Avoid over-correcting Exp 18's C-term by weakening the mid-doubt lone dissenter: Exps 13/14 pin that quantity near .47
inus.55, so the T
inus C gap must be closed from the T side (flat opposition discount), not by suppressing C.

If these three adjustments do not improve aggregate loss, the fallback is to keep only adjustment (1) 
inus the opposition-flatness is the single best-supported deviation, being the only one that explains Exp 15, Exp 18-T and Exp 8/9 simultaneously.

**Outcome of your advice:** iter 1 candidate loss=0.0672 -> iter 2 candidate loss=0.0600 -> the gate marked it ACCEPTED.

### Iteration 2
Verdict: regenerate
Interpretation: SSG-2 (iter 2) is the best member of the family so far and was ACCEPTED (0.0672 -> 0.0600). The sharpened oddness contrast did what it was advertised to do: Exp 15 rose .707 -> .750, Exp 18's T-C rose .174 -> .250, Exp 12 rose .182 -> .218, Exp 8 came down .823 -> .810, and Exps 1 (.279 vs .282), 4 (.125 vs .150), 5 (.753 vs .743), 6 (.493 vs .507), 10 (.415 vs .418), 11 (.612 vs .593) and 16 (.8225 vs .826) are essentially on target. Faithfulness to the arbiter's RELATIVE-SHARE GATING prescription is intact: graded sigmoid gate on an oddness share, opposition-only (near-flat) degradation of the one-reason limb, divisively normalised compensatory limb, degeneracy/tally fallback for exact repeats. No family drift.

The residuals are now small but structured, and they cluster in two places. (a) The .55 anchor still under-adjudicates: Exp 15 = .750 vs .862 (-.112). Note that in Exp 15 the anchor is almost always the lone dissenter (k_conf = 1), so rho_opp is inert there — the limiting quantity is P_trig = max_j g_j itself. With v_crit = .578 and w_h = .0125, g(.55) = sigmoid(.028/.0125) = .90, which hard-caps pi_one at .90 and therefore caps the predicted follow rate near .78-.80 even before any dilution. The .52 anchor designs (Exp 16 = .8225 vs .826) fit precisely because g(.52) ~ 1. So the miss is a *scandal-function calibration* miss at v = .55, not a share or opposition miss.

(b) The recency tilt of the integration limb has the wrong sign relative to the data for mid-doubt lone dissenters. Real: Exp 13 (early .68 dissenter) = .546 > Exp 17 (last-column .66 dissenter) = .493 ~ Exp 14 (.468). Model: Exp 13 = .453 < Exp 17 = .561 > Exp 14 = .536. The ordering is inverted, and the three errors (-.093, +.068, +.069) are all attributable to lam = .18-.26 over-weighting late columns. The same over-weighted late .68 row inflates Exp 18's C-term and thus keeps T-C at .250 instead of .318, and it pushes Exp 7 (.459 vs .438) and Exp 14 up. Fixing lam is therefore a single knob that pays off on four experiments at once.

(c) Minor: Exps 3 (.234 vs .286) and 12 (.218 vs .261) remain slightly too anti-validity-deterministic, and Exps 8/9 (+.040/+.013) are still a touch too last-row-deterministic among co-scandalous rows.
Rationale: The candidate was ACCEPTED, so keep it as the base; but three cheap, non-overlapping in-family recalibrations remain, and one of them (recency) is diagnosably mis-signed rather than merely mis-scaled. Keep predict/policy exactly as written (oddness-share gate, log-sigmoid scandal, opposition-only near-flat discount, divisive normalisation, degeneracy fallback) and move only parameter ranges:

1. NEW, highest-value knob — reduce the integration recency lam from [0.18, 0.26] to ~[0.10, 0.17]. Justification above: the model currently ranks late mid-doubt dissenters above early ones (Exp 17 .561 > Exp 13 .453) while humans do the opposite (.493 vs .546). Expected: Exp 13 up ~.05, Exp 17 down ~.05, Exp 14 down ~.04, Exp 7 down ~.02 toward .438, and Exp 18's C-term falls so T-C rises toward .29. Watch Exp 10 (.418) and Exp 11 (.593), which are recency-sensitive — if they degrade by more than ~.02, stop at lam ~ .17 rather than going lower. Do NOT compensate by changing gamma_w, which is currently delivering Exps 10/11/14.

2. Raise g(.55) toward 1 so the .55 anchor can actually adjudicate: tighten w_h from [0.010, 0.015] to ~[0.008, 0.011] and/or nudge v_crit from [0.572, 0.586] to ~[0.578, 0.588]. This lifts P_trig for Exp 15 from ~.90 to ~.96-.98 (Exp 15 -> ~.80) while *increasing* the dilution of the .60 bystander in Exp 2 (g(.60) .15 -> ~.18), which is welcome because Exp 2 now overshoots (+.029). Do not touch c_share/w_share/gate_floor — the g-weighted share definition and the floor are what buy Exps 2 and 4, and I do not want to relitigate the gate threshold after last round's gate_floor move already landed.

3. Small continuation of the (previously ACCEPTED) sigma direction: sigma [0.52, 0.70] -> ~[0.58, 0.78]. It moved Exp 12 .182 -> .218 and Exp 3 up last round; another modest step should close most of the remaining -.04/-.05 on Exps 12/3 and lift Exp 4 (.125 -> ~.14, real .150) while nudging Exp 5 down (.753 -> ~.748, real .743). Keep beta unchanged so the direction is unambiguous.

4. Optional, only if the above leave headroom: lower mu from [0.68, 0.92] to ~[0.52, 0.76] to trim the +.040 overshoot on Exp 8 and +.013 on Exp 9 — mu only arbitrates BETWEEN co-scandalous rows, so this cannot touch the single-anchor designs (Exps 13-18).

Explicitly do NOT touch rho_opp again. I pushed it flatter last round and it is now inert on the experiment it was supposed to fix (Exp 15 is k_conf = 1); further flattening would only perturb Exps 16/18 with no upside. Likewise do not attack Exp 18's gap from the C side by suppressing mid-doubt dissenters outright — Exps 13/14 pin that quantity at .47-.55; the gap must close via the lam fix (which lowers C for the *last-column* .68 row specifically) plus the Exp-15-style P_trig fix on the T side.

**Outcome of your advice:** iter 2 candidate loss=0.0600 -> iter 3 candidate loss=0.0506 -> the gate marked it ACCEPTED.

### Iteration 3
Verdict: regenerate
Interpretation: SSG-3 (iter 3) is the best member of the family so far (0.0672 -> 0.0600 -> 0.0506, ACCEPTED) and it is faithful to the arbiter's relative-share gating prescription: graded sigmoid gate on a g-weighted oddness SHARE, one-reason limb degraded by opposition only (not display length), divisively normalised compensatory limb, degeneracy/tally fallback. My two previous pushes both paid off, and the diagnostics confirm why: the lam reduction inverted the bad ordering on mid-doubt lone dissenters (Exp 17 .561 -> .491 vs real .493; Exp 14 .536 -> .516 vs .468), the w_h/v_crit tightening lifted Exp 15 (.750 -> .780) without hurting Exp 16 (.8495 vs .826), and Exp 4 landed almost exactly (.153 vs .150), with Exps 6, 7, 9, 10, 11, 17 all within ~.014.

The residuals are now few and structured. (a) A coherent 'compensatory limb is too deterministic on CONFLICT displays' cluster: Exp 1 .2515 vs .282 (regressed this round from .2785), Exp 3 .249 vs .286, Exp 12 .200 vs .261 (moved the WRONG way this round despite the sigma bump), Exp 13 .450 vs .546. All four are under-shot in the same direction — the model is more extremely anti-validity / more decided than subjects on conflict trials. Notably Exp 13 did not respond at all to the lam fix, so its miss is not positional: it is the level of determinism of the integration verdict. (b) The mirror-image overshoot on the one lone-dissenter design where subjects are BELOW chance: Exp 14 .516 vs .468. A single knob (the conflict-dependent shrink toward chance) moves (a) up and (b) down simultaneously. (c) Adjudication level is still slightly short where the anchor faces a coalition: Exp 15 .780 vs .862, Exp 18 T-C .2575 vs .3183, while the co-scandalous designs are over: Exp 8 .8163 vs .7697 (the mu trim bought essentially nothing, .810 -> .816), Exp 16 .8495 vs .826. (d) Minor: dominance accuracy is a touch high (Exp 5 .767 vs .743) and Exp 2 still overshoots by +.028.
Rationale: The candidate was ACCEPTED, so the base is safe, but there is one clearly identified, previously-untouched in-family knob that moves FIVE experiments in the right direction at once. Keep `predict` and `policy` byte-for-byte (oddness-share gate, log-sigmoid scandal, opposition-only near-flat discount, divisive normalisation, degeneracy fallback) and move only parameter ranges:

1. HIGHEST VALUE, NEW KNOB — lower rho_c from [0.73, 0.83] to ~[0.60, 0.73]. rho_c^k_conf is the conflict-specific shrink of the compensatory verdict toward chance; it has never been touched in this loop. Raising that shrink lifts every under-shot conflict metric toward .5 — Exp 1 (.2515 -> ~.27), Exp 3 (.249 -> ~.27), Exp 12 (.200 -> ~.23), Exp 13 (.450 -> ~.48) — and simultaneously PULLS DOWN the one over-shot lone-dissenter metric, Exp 14 (.516 -> ~.50, real .468), which no other knob can do (gamma_w/lam move 13 and 14 together). Because k_conf = 0 on dominance displays it is completely inert on Exp 5, and it barely touches Exps 11/15/16/18, which are one-reason dominated. Expected cost is small: Exp 4 (.153, real .150) and Exp 7 (.441, real .438) each drift up ~.01-.02. Note that last round's sigma bump did NOT deliver on Exps 3/12 (12 actually fell), so do not push sigma further — use rho_c instead.

2. Second — close the remaining adjudication shortfall on Exps 15 (-.082) and 18-T (-.061) with a coordinated pair rather than a single lever: lower eps_t modestly ([0.23,0.33] -> ~[0.18,0.28]) to raise one-reason fidelity, and pay for the resulting inflation of the co-scandalous designs by cutting mu further ([0.55,0.80] -> ~[0.30,0.60]) so the softmax spreads across the three coin-flippers in Exps 8/9 (Exp 8 is +.047 too high; the last mu trim was too timid to bite). Net target: Exp 15 ~.82, Exp 18 T-C ~.29, Exp 8 ~.79, Exp 9 ~.80, Exp 16 up by at most ~.02 (acceptable given its residual is only +.024).

3. Optional trim — raise eps0 slightly ([0.22,0.30] -> ~[0.25,0.33]) to bring dominance accuracy down (Exp 5 .767 -> ~.75, real .743); this also nudges Exps 1/3/12 toward .5, reinforcing item 1.

Explicitly DO NOT touch: rho_opp (I flattened it in iter 1 — it worked; reversing now would be oscillation), c_share / w_share / gate_floor (they buy Exps 2 and 4, pi_10's failures), gamma_w and lam (just calibrated and now delivering Exps 10/11/14/17), and w_h / v_crit (just tightened; Exps 2/16 are near-target). Do not attack Exp 18's gap from the C side — Exps 13/14 pin that quantity near .47-.55.

If the combined edit fails to beat 0.0506, the minimal fallback is item 1 alone: the rho_c reduction is the single best-supported deviation, being the only one that explains Exps 1, 3, 12, 13 and 14 with one sign.

**Outcome of your advice:** iter 3 candidate loss=0.0506 -> iter 4 candidate loss=0.0451 -> the gate marked it ACCEPTED.

### Iteration 4 (most recent)
Verdict: regenerate
Interpretation: SSG-4 is the best member of the family so far (0.0672 → 0.0600 → 0.0506 → 0.0451, all ACCEPTED) and it remains faithful to the arbiter's RELATIVE-SHARE GATING prescription: a graded sigmoid gate on a g-weighted oddness SHARE, a one-reason limb degraded by opposition only (never by display length), a divisively normalised compensatory limb with a conflict-graded leak, and a degeneracy/tally fallback. No family drift. Ten of eighteen experiments are now within ~.02 (Exps 4, 5, 6, 7, 9, 10, 11, 17, 18, 2), which is close to between-subject noise.

The iter-4 edit bundle did NOT do what I predicted, and the diagnosis matters. My rho_c push was supposed to lift Exps 1/3/12 toward chance; instead Exp 1 was flat (.2515 → .2505), Exp 3 moved the WRONG way (.249 → .223) and Exp 12 was flat (.200 → .198). The reason is clear in the code: on those designs a near-chance row (.55 in Exp 1, .52/.58 in Exp 3, .51 in Exp 12) makes P_trig ≈ 1 and the oddness share ≈ 1, so a large fraction of the diagnostic trials is decided by the ADJUDICATION limb, not the integration limb. rho_c therefore cannot touch them, while the simultaneous eps_t drop (.23-.33 → .19-.29) made the adjudication verdict *more* anti-validity — swamping the rho_c shrink. The net loss gain came almost entirely from Exps 15 (.780 → .807), 18-T−C (.2575 → .2975) and 13 (.450 → .479).

The residual structure is now clean and, for the first time, internally consistent along a single axis — opposition-coalition size. Model is TOO one-reason / too anti-validity exactly where the adjudicating row faces a coalition of ≥2 (Exp 16 +.035 with k_conf ≥ 2 by construction, Exp 8 +.037, Exp 3 −.062, Exp 12 −.063, Exp 1 −.032, Exp 6 −.030), and it is still slightly too weak where the anchor stands essentially ALONE (Exp 15 −.055, mostly k_conf = 1; Exp 18-T −.021, k_conf ≤ 1 by the metric's own filter). Exps 13 (−.067) and 14 (+.038) straddle chance in opposite directions with the same mechanism (lone low-validity dissenter vs. a more-valid coalition) and high between-subject variance (.013-.014); within this family they are not separably fittable and are probably near noise.
Rationale: The candidate was ACCEPTED and should remain the base — keep `predict`/`policy` byte-for-byte. One more parameter-range move is worth trying, and for the first time the evidence points at a knob whose effects are *sign-consistent across six experiments and inert on the ones that are already right*.

1. HIGHEST VALUE — partially re-steepen rho_opp: [0.88, 0.96] → ~[0.82, 0.90]. I must flag this explicitly: in iter 1 I asked for the opposite (flattening), and that bundle was ACCEPTED — but I already noted in iter 2 that flattening was NOT what fixed Exp 15 (k_conf = 1 there, so rho_opp is inert). The evidence has now flipped on the experiments where rho_opp actually bites. Because fid = (1−eps_t)·rho_opp^(k_conf−1), a modest steepening (a) pulls Exp 16 down (~−.03; its metric filters to k_conf ≥ 2 and it is +.035 too high), (b) pulls Exp 8 down (~−.03; +.037 too high), (c) shrinks the adjudication verdict toward chance on the 2-vs-2 / 2-vs-3 conflict trials that drive Exps 1, 3, 6 and 12, all of which are under-shot in the same anti-validity direction, and (d) is EXACTLY inert on the designs I do not want to disturb: Exp 15 and Exp 18-T (k_conf ≤ 1), Exps 13/14 (k_conf = 1), Exp 5 (k_conf = 0), and Exp 17 (gate shut). This is the only single knob with that inertness profile. Do not go below ~.82 — that is roughly the pre-iter-1 level, and Exp 9 (.8078 vs .8189) is already marginally low and will follow Exp 8 down.

2. Do NOT push rho_c or sigma further. Both have now been tried (iters 2 and 3) as fixes for Exps 3/12 and both failed for the structural reason given above: those diagnostic trials are adjudication trials, not integration trials. Leave rho_c at [0.62, 0.75] and sigma at [0.58, 0.78].

3. Do NOT move eps_t again in either direction. The last drop bought Exps 15/18 and cost Exps 1/3/12; the rho_opp change above recovers the cost without giving back the benefit, so eps_t should stay at [0.19, 0.29]. Likewise leave c_share / w_share / gate_floor (they buy Exps 2 and 4, which are pi_10's failures) and gamma_w / lam (delivering Exps 10/11/14/17) untouched.

4. Optional micro-trim only if the above leaves headroom: mu is now [0.35, 0.62]; the last cut bought ~.01 on Exp 8, and item 1 should finish the job, so do not cut it again — further spreading would start to hurt Exp 9, which is already .011 low.

Finally, treat Exps 13 (−.067) and 14 (+.038) as a jointly irreducible pair in this family: they are the same lone-low-validity-dissenter configuration with human values on opposite sides of chance and large between-subject variance. Do not introduce a new term to separate them; any knob that lifts 13 lifts 14 by a similar amount and the squared-error trade is roughly neutral. If the rho_opp move does not beat 0.0451, ship the current SSG-4 unchanged.

**Outcome of your advice:** iter 4 candidate loss=0.0451 -> CURRENT candidate loss=0.0422 -> the gate marked it ACCEPTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "SSG-5 is the best member of the family so far (0.0672 \u2192 0.0600 \u2192 0.0506 \u2192 0.0451 \u2192 0.0422, every step ACCEPTED) and it remains fully faithful to the arbiter's RELATIVE-SHARE GATING prescription: a graded sigmoid gate on a g-weighted oddness SHARE, a one-reason limb degraded by opposition only (never by display length), a divisively normalised compensatory limb with a conflict-graded leak, and a degeneracy/tally fallback for the near-repeat validity designs. No family drift, no architectural churn \u2014 only the single rho_opp range moved, exactly as I asked.\n\nThe iter-4\u21925 edit behaved roughly as advertised on the anti-validity cluster: Exp 3 recovered strongly (.223 \u2192 .266 vs real .286), Exp 12 moved up (.198 \u2192 .206 vs .261), Exp 1 up slightly (.2505 \u2192 .2542 vs .282), Exp 13 up materially (.479 \u2192 .521 vs .546), Exp 16 came down into range (.8605 \u2192 .844 vs .826). It did NOT do what I predicted on Exp 8 (.8063 \u2192 .8134, still +.044 too high) \u2014 so the co-scandalous designs are not being governed by rho_opp the way I assumed, and Exp 15 gave back a hair (.807 \u2192 .804).\n\nResidual structure is now small and, importantly, no longer aligned on a single axis. The remaining errors split into three groups: (i) an integration-limb determinism cluster that is uniformly too far from chance \u2014 Exp 12 \u2212.055, Exp 1 \u2212.028, Exp 3 \u2212.020, Exp 7 +.023 (too late-row-decided), Exp 5 +.027 (dominance accuracy too high), Exp 14 +.039 (above chance where subjects are below); (ii) an adjudication cap on the .55 anchor \u2014 Exp 15 \u2212.058, Exp 18 T\u2212C \u2212.034, both of which are now limited by fid = (1\u2212eps_t)\u00b7rho_opp^(k_conf\u22121) and cannot be lifted by c_share/w_share/gate_floor (share \u2248 1 there, so the gate is already saturated); (iii) the co-scandalous near-degenerate pair, Exp 8 +.044 / Exp 9 \u2212.013, which pull in OPPOSITE directions and therefore cannot both be fixed by eps_t or mu. Ten to twelve of eighteen experiments now sit inside ~.02, at or near between-subject noise.",
  "verdict": "regenerate",
  "rationale": "The candidate was ACCEPTED and must remain the base \u2014 keep `predict` and `policy` byte-for-byte. One previously-untouched knob still has a sign-consistent payoff across five or six experiments, so one more cheap parameter-range iteration is worth it.\n\n1. HIGHEST VALUE, NEW KNOB \u2014 raise the compensatory lapse eps0 from [0.22, 0.30] to ~[0.26, 0.34]. eps0 enters only through keep_c, i.e. it shrinks the INTEGRATION verdict toward chance and is completely inert on the adjudication limb. Its effect is sign-correct on the whole of residual group (i) simultaneously: Exp 5 (.769 \u2192 ~.75, real .743), Exp 1 (.254 \u2192 ~.27, real .282), Exp 3 (.266 \u2192 ~.28, real .286), Exp 12 (.206 \u2192 ~.22, real .261), Exp 7 (.462 \u2192 ~.455, real .438), Exp 14 (.506 \u2192 ~.502, real .468). The only debits are small: Exp 13 drifts ~.003 down from .521 (real .546) and Exp 10 may drift ~.005 from .420 (real .418). This is the one lever I have not yet spent, and unlike the sigma/rho_c attempts of iters 2\u20133 it does not have to reach the trials that the gate routes to adjudication \u2014 it acts on the residual compensatory mixture weight (1\u2212pi_one) present on EVERY conflict display plus all of the unanimous ones.\n\n2. DO NOT move eps_t or rho_opp again. eps_t was dropped in iter 3 (paid for Exps 15/18) and rho_opp was re-steepened in iter 5 (paid for Exps 3/12/13/16); moving either now would be exactly the oscillation I warned myself against, and the Exp-15 (\u2212.058) / Exp-8 (+.044) tension is structurally unresolvable with those two knobs since they push both experiments the same way. Treat Exp 15's remaining shortfall as the family's accepted cost of keeping Exp 8 near .81.\n\n3. DO NOT touch c_share / w_share / gate_floor (they are what buy Exps 2 and 4, pi_10's clearest failures), gamma_w / lam (delivering Exps 10/11/14/17 within ~.015), or w_h / v_crit (Exp 16 is now on target and Exp 2's +.031 overshoot is only ~1.5 between-subject SDs).\n\n4. Optional micro-trim ONLY if item 1 leaves headroom and Exp 8 is still >+.04: nudge mu from [0.35, 0.62] to [0.30, 0.55]. Expect ~\u2212.01 on Exp 8 and ~\u2212.01 on Exp 9 (which is already .013 low), so this is close to a wash \u2014 do it only as a second-order tweak, never together with an eps_t change.\n\nTreat Exps 13 (\u2212.025) and 14 (+.039) as the jointly irreducible lone-dissenter pair they have proved to be across four iterations; do not add a new term to separate them.\n\nIf the eps0 move does not beat 0.0422, ship SSG-5 unchanged \u2014 the family is clearly at the flat part of its improvement curve and further edits risk trading noise for noise."
}
```

## Usage

```json
{
  "input_tokens": 53676,
  "output_tokens": 5621
}
```
