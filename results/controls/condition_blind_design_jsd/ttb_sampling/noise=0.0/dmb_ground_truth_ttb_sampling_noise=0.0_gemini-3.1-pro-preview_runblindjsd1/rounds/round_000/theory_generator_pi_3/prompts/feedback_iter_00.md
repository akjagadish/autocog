# feedback_iter_00

## System Prompt

You are a renowned cognitive scientist critiquing a freshly proposed candidate theory and model in the Decision Making (Binary Features) domain.

The candidate has been simulated on every previously run experiment. For each experiment you are shown the design, the metric, the value the metric takes on real (human / ground-truth) data, and the value it takes on the candidate's simulated data.

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
- THEORY 1 = `pi_1`
- THEORY 2 = `pi_2`
- The recommendation below acts on THEORY 1 (= `pi_1`).

Propose the 'Take-The-Best' (TTB) heuristic. Unlike Tallying (which weights all cues equally) and WADD (which integrates all cues compensatorily), TTB ranks cues by their validity. It compares options sequentially starting from the most valid cue, and bases the decision entirely on the first cue that discriminates between the options. If the most valid cue ties, it moves to the second most valid cue, and so on. This will provide a strong non-compensatory benchmark.


## CANDIDATE THEORY
Take-The-Best (TTB) is a non-compensatory fast-and-frugal heuristic. People rank features by their subjective validity and compare options sequentially. The decision is based entirely on the first feature that discriminates between the options, ignoring all remaining features. If all features tie, the decision maker guesses randomly. Response noise is captured by a uniform lapse rate.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"TTB expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    validities = np.asarray(parameters["validities"], dtype=float)
    
    # Rank features by validity in descending order
    order = np.argsort(validities)[::-1]
    
    p_core = np.array([0.5, 0.5])
    for idx in order:
        if a[idx] > b[idx]:
            p_core = np.array([1.0, 0.0])
            break
        elif b[idx] > a[idx]:
            p_core = np.array([0.0, 1.0])
            break
            
    epsilon = float(parameters["epsilon"])
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    probabilities = np.asarray(probabilities, dtype=np.float64)
    probabilities /= probabilities.sum()
    return int(np.random.choice(len(probabilities), p=probabilities))

`parameters`:
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`:
Implements the Take-The-Best heuristic as requested by the arbiter. It provides a purely non-compensatory benchmark by ranking cues according to their validity and terminating the search at the first cue that strictly discriminates between the options. A lapse rate parameter 'epsilon' is added to account for response noise.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1 (current candidate you are grading): loss=0.2369 -> ACCEPTED
Running-best (last accepted) base: iter 1 at loss=0.2369.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 1, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 1, 0]
  A=[0, 1, 0, 1]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 0, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 0, 0, 1]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 0, 0]  B=[1, 1, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 1, 1, 1]
  A=[1, 1, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[1, 0, 0, 0]
  A=[1, 1, 0, 1]  B=[1, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 0, 1, 1]
  A=[1, 1, 0, 1]  B=[0, 1, 1, 0]

**Metric**
```python
P_REF = {'((0, 1, 0, 0), (0, 1, 1, 0))|0': 0.8471337579617835, '((0, 1, 0, 0), (0, 1, 1, 0))|1': 0.8368298368298368, '((1, 1, 0, 1), (0, 1, 1, 0))|0': 0.17772215269086358, '((1, 1, 0, 1), (0, 1, 1, 0))|1': 0.16583416583416583, '((1, 0, 0, 1), (0, 0, 1, 0))|0': 0.15309734513274337, '((1, 0, 0, 1), (0, 0, 1, 0))|1': 0.1537313432835821, '((0, 0, 0, 1), (1, 1, 0, 0))|0': 0.8552522746071133, '((0, 0, 0, 1), (1, 1, 0, 0))|1': 0.8324873096446701, '((1, 0, 1, 0), (0, 0, 0, 0))|0': 0.16329479768786126, '((1, 0, 1, 0), (0, 0, 0, 0))|1': 0.1299638989169675, '((0, 0, 1, 0), (0, 1, 1, 1))|0': 0.8578052550231839, '((0, 0, 1, 0), (0, 1, 1, 1))|1': 0.8640093786635404, '((0, 0, 0, 0), (1, 1, 0, 0))|0': 0.8636779505946935, '((0, 0, 0, 0), (1, 1, 0, 0))|1': 0.8458274398868458, '((1, 1, 1, 1), (0, 0, 1, 0))|0': 0.11648568608094768, '((1, 1, 1, 1), (0, 0, 1, 0))|1': 0.16010165184243966, '((1, 1, 0, 1), (1, 1, 1, 0))|0': 0.49140271493212667, '((1, 1, 0, 1), (1, 1, 1, 0))|1': 0.5179856115107914, '((1, 1, 1, 0), (0, 1, 1, 1))|0': 0.5100502512562815, '((1, 1, 1, 0), (0, 1, 1, 1))|1': 0.49302788844621515, '((1, 1, 1, 1), (0, 0, 0, 1))|0': 0.10619469026548672, '((1, 1, 1, 1), (0, 0, 0, 1))|1': 0.11892963330029732, '((0, 1, 0, 1), (1, 1, 0, 0))|0': 0.512781954887218, '((0, 1, 0, 1), (1, 1, 0, 0))|1': 0.474468085106383, '((1, 1, 1, 1), (0, 0, 0, 0))|0': 0.12003311258278146, '((1, 1, 1, 1), (0, 0, 0, 0))|1': 0.13175675675675674, '((1, 0, 0, 1), (1, 0, 0, 0))|0': 0.14905814905814907, '((1, 0, 0, 1), (1, 0, 0, 0))|1': 0.15889464594127806, '((1, 0, 1, 1), (1, 1, 1, 0))|0': 0.508296943231441, '((1, 0, 1, 1), (1, 1, 1, 0))|1': 0.4900763358778626, '((0, 0, 1, 1), (1, 0, 1, 1))|0': 0.8048780487804879, '((0, 0, 1, 1), (1, 0, 1, 1))|1': 0.8489451476793249}
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

```

**Observed (real) value:** 0.0205 (var=0.0002)
**Candidate (simulated) value:** 0.0230 (var=0.0002)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0007 (var=0.0001)
- pi_2: 0.0071 (var=0.0004)

### Experiment 2
**Design**
  A=[1, 1, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 1, 0]  B=[1, 0, 1, 0]
  A=[1, 0, 1, 1]  B=[0, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 1]
  A=[0, 0, 0, 0]  B=[1, 0, 1, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 1, 0]
  A=[1, 0, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 1]  B=[0, 1, 0, 0]
  A=[0, 1, 0, 1]  B=[0, 0, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 0]  B=[0, 0, 0, 0]
  A=[0, 0, 0, 0]  B=[0, 1, 1, 0]
  A=[0, 0, 0, 1]  B=[0, 1, 1, 1]
  A=[0, 1, 0, 1]  B=[0, 0, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 1, 1, 1]
  A=[1, 1, 1, 0]  B=[1, 0, 1, 0]

**Metric**
```python
P_REF = {'((0, 0, 0, 1), (0, 0, 1, 1))|0': 0.7913950456323338, '((0, 0, 0, 1), (0, 0, 1, 1))|1': 0.7831558567279767, '((1, 0, 1, 1), (1, 0, 0, 0))|0': 0.2125, '((1, 0, 1, 1), (1, 0, 0, 0))|1': 0.17314814814814813, '((0, 1, 0, 1), (0, 0, 1, 0))|0': 0.3384201077199282, '((0, 1, 0, 1), (0, 0, 1, 0))|1': 0.35276967930029157, '((0, 0, 0, 0), (0, 1, 1, 0))|0': 0.8560700876095119, '((0, 0, 0, 0), (0, 1, 1, 0))|1': 0.8271728271728271, '((1, 1, 1, 0), (1, 0, 1, 0))|0': 0.22364217252396165, '((1, 1, 1, 0), (1, 0, 1, 0))|1': 0.206984667802385, '((0, 1, 0, 1), (0, 0, 0, 1))|0': 0.2425249169435216, '((0, 1, 0, 1), (0, 0, 0, 1))|1': 0.21962095875139354, '((0, 0, 1, 1), (1, 1, 0, 1))|0': 0.7389858686616791, '((0, 0, 1, 1), (1, 1, 0, 1))|1': 0.6549413735343383, '((1, 0, 0, 1), (0, 1, 0, 0))|0': 0.2998805256869773, '((1, 0, 0, 1), (0, 1, 0, 0))|1': 0.3052959501557632, '((1, 1, 0, 1), (0, 1, 1, 1))|0': 0.45555555555555555, '((1, 1, 0, 1), (0, 1, 1, 1))|1': 0.45308641975308644, '((0, 0, 0, 0), (1, 0, 1, 1))|0': 0.8474387527839644, '((0, 0, 0, 0), (1, 0, 1, 1))|1': 0.835920177383592, '((0, 1, 0, 1), (1, 1, 1, 1))|0': 0.8377125193199382, '((0, 1, 0, 1), (1, 1, 1, 1))|1': 0.8475967174677609, '((0, 1, 1, 0), (0, 0, 0, 0))|0': 0.16120906801007556, '((0, 1, 1, 0), (0, 0, 0, 0))|1': 0.17693836978131214, '((0, 1, 0, 0), (0, 1, 1, 0))|0': 0.7583444592790387, '((0, 1, 0, 0), (0, 1, 1, 0))|1': 0.7916270218839201, '((0, 0, 0, 1), (0, 1, 1, 1))|0': 0.8501026694045175, '((0, 0, 0, 1), (0, 1, 1, 1))|1': 0.8317191283292978, '((1, 0, 1, 1), (0, 1, 0, 1))|0': 0.2862669245647969, '((1, 0, 1, 1), (0, 1, 0, 1))|1': 0.24551831644583008, '((0, 1, 1, 0), (1, 0, 1, 0))|0': 0.4927675988428158, '((0, 1, 1, 0), (1, 0, 1, 0))|1': 0.583224115334207}
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

```

**Observed (real) value:** 0.0172 (var=0.0002)
**Candidate (simulated) value:** 0.0261 (var=0.0002)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0015 (var=0.0003)
- pi_1: 0.0071 (var=0.0001)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The candidate perfectly implements the Take-The-Best (TTB) heuristic as prescribed by the arbiter. It sorts cues by validity, compares them sequentially, and terminates the search at the first discriminating cue. It also correctly handles ties (by moving to the next cue or guessing if all tie) and incorporates a lapse rate (epsilon) for response noise. The resulting simulated values provide the requested non-compensatory benchmark.",
  "verdict": "continue",
  "rationale": "The candidate accurately implements the arbiter's requested Take-The-Best mechanism without drifting into other families. The logic for sequential search, early stopping, and uniform lapse rate is sound. As this provides the exact benchmark requested, it is good to proceed."
}
```

## Usage

```json
{
  "prompt_token_count": 7308,
  "candidates_token_count": 162,
  "total_token_count": 8161
}
```
