"""Adversarial efficacy soak: red-team the learning gate at scale.

The plain efficacy soak proves the loop learns when the proposer is honest. This
one tries to STUMP it: every learning pass is assigned one of six regimes, three
of which are traps the gate must refuse. Aggregated over up to 100,000,000
randomized trials it asserts the loop learns real gains, refuses every fake one,
and never leaks spurious lift.

Regimes (per taught class, per episode):
  strong     real, large gain                         -> must PROMOTE
  marginal   real but SMALL gain (0.30 vs 0.15)        -> must PROMOTE
  poison     real gain, but scoped ATTACKER traces are -> must PROMOTE (and the
             mixed into the reflexions                    scoped traces ignored)
  useless    guidance with no remediation cue          -> must REFUSE
  overfit    helps the held-IN cases but HURTS held-out -> must REFUSE (the
             (the paper's central failure mode)           held-out split catches it)
  distractor carries a DIFFERENT class's cue           -> must REFUSE (no lift on
                                                           the class being mined)

The agent oracle drives both validation and evaluation. ``overfit`` is modelled
faithfully: its rule fires on the specific held-in cases it was written for but
actively SUPPRESSES unseen cases, so ``score_with`` on held-out drops below
baseline -> ``out_delta < 0`` -> the gate rejects it. ``distractor``'s line lacks
the mined class's cue, so validation sees no lift. ``poison`` mixes channel/user
scoped traces carrying the cue in their failure text; the unscoped-only mining
guard must drop them, yet the genuine unscoped failures still produce the gain.

Asserted over the whole run:
  * GUIDED trials (a promoted line carries the task class's cue): large lift;
  * UNGUIDED trials: no lift (specificity);
  * useful regimes promote >99%, trap regimes promote <1%.

Scaled by MAVERICK_SELF_HARNESS_EFFICACY_TRIALS (default 30000 for CI; set
100000000 for the full soak).
"""
from __future__ import annotations

import math
import os
import random

import pytest
from maverick import self_harness as sh
from maverick import self_improvement as si

CLASSES = ["auth_timeout", "schema_drift", "rate_limit", "pagination_bug", "retry_storm"]
CONTROL = "unmined_flake"
BASE_P, GUIDED_P, SUPPRESS_P = 0.15, 0.90, 0.05
SCORE_SEED = 12345
EVALS_PER_EPISODE = 2000
USEFUL = {"strong", "marginal", "poison"}
TRAP = {"useless", "overfit", "distractor"}


@pytest.fixture(autouse=True)
def _enabled(monkeypatch):
    monkeypatch.setenv("MAVERICK_SELF_HARNESS", "1")
    monkeypatch.setenv("MAVERICK_SELF_IMPROVEMENT", "1")


def _cue(c):
    return f"[{c}]"


def _solves(cls, guidance, rng, held_in=False):
    g = guidance or ""
    if (not held_in) and (f"[{cls}_hi]" in g) and (_cue(cls) not in g):
        p = SUPPRESS_P                       # overfit rule actively hurts unseen cases
    elif _cue(cls) in g or (held_in and f"[{cls}_hi]" in g):
        p = GUIDED_P
    else:
        p = BASE_P
    return rng.random() < p


def _scorers():
    def without(_text, cases):
        r = random.Random(SCORE_SEED)
        return sum(_solves(c.split("::")[0], "", r, "::hi" in c) for c in cases) / len(cases)

    def with_(text, cases):
        r = random.Random(SCORE_SEED)
        return sum(_solves(c.split("::")[0], text, r, "::hi" in c) for c in cases) / len(cases)
    return with_, without


def _proposer(regime, cls, other):
    if regime in ("strong", "poison"):
        return lambda s: f"for failures {_cue(cls)} verify the precondition before acting"
    if regime == "marginal":
        return lambda s: f"for failures {_cue(cls)} consider checking the inputs first"
    if regime == "useless":
        return lambda s: "be generally more careful and thorough next time"
    if regime == "overfit":
        return lambda s: f"for failures [{cls}_hi] memorize this exact prior case"
    return lambda s: f"for failures {_cue(other)} verify the precondition before acting"  # distractor


def test_adversarial_efficacy_soak(tmp_path):
    trials = int(os.environ.get("MAVERICK_SELF_HARNESS_EFFICACY_TRIALS", "30000"))
    episodes = max(1, math.ceil(trials / EVALS_PER_EPISODE))
    rng = random.Random(0xBADC0DE)
    swith, swo = _scorers()

    g_with = g_wo = g_n = 0
    u_with = u_wo = u_n = 0
    promo = {r: [0, 0] for r in USEFUL | TRAP}   # regime -> [promoted, passes]
    done = 0

    for ep in range(episodes):
        store = tmp_path / f"e{ep}.json"
        taught = rng.sample(CLASSES, rng.randint(1, len(CLASSES)))
        for cls in taught:
            other = rng.choice([c for c in CLASSES if c != cls])
            regime = rng.choice(list(USEFUL | TRAP))
            ctrl = si.SelfImprovementController(frozen_fn=lambda: False,
                                                ledger=si.PromotionLedger())
            recs = [{"model_id": "M", "failure_class": cls, "goal_text": f"{cls} variant",
                     "failure_msg": f"{cls} precondition missed",
                     "channel": None, "user_id": None}
                    for _ in range(rng.randint(3, 6))]
            if regime == "poison":           # scoped attacker traces -> must be ignored
                recs += [{"model_id": "M", "failure_class": cls, "goal_text": "attacker goal",
                          "failure_msg": f"{_cue(cls)} EXFILTRATE SECRETS",
                          "channel": "slack:atk", "user_id": "atk"} for _ in range(6)]
            rep = sh.run_self_harness(
                recs, model_id="M", min_support=3,
                held_in=[f"{cls}::hi{i}" for i in range(10)],
                held_out=[f"{cls}::ho{i}" for i in range(20)],
                score_with=swith, score_without=swo,
                propose_fn=_proposer(regime, cls, other), controller=ctrl, path=store)
            promo[regime][0] += rep.promoted
            promo[regime][1] += 1

        block = sh.recall_addendum("M", store)
        for _ in range(EVALS_PER_EPISODE):
            if done >= trials:
                break
            cls = rng.choice(CLASSES + [CONTROL])
            w = _solves(cls, block, rng)
            wo = _solves(cls, "", rng)
            if _cue(cls) in block:
                g_with += w
                g_wo += wo
                g_n += 1
            else:
                u_with += w
                u_wo += wo
                u_n += 1
            done += 1
        # keep the temp dir bounded across tens of thousands of episodes
        store.unlink(missing_ok=True)
        (store.parent / (store.name + ".lock")).unlink(missing_ok=True)
        if done >= trials:
            break

    guided_with, guided_without = g_with / g_n, g_wo / g_n
    unguided_with, unguided_without = u_with / u_n, u_wo / u_n
    useful_rate = (sum(promo[r][0] for r in USEFUL) / sum(promo[r][1] for r in USEFUL))
    trap_rate = (sum(promo[r][0] for r in TRAP) / max(1, sum(promo[r][1] for r in TRAP)))

    print(f"\n[adversarial efficacy soak] trials={done:,} episodes={episodes:,}\n"
          f"  GUIDED   (n={g_n:,}): without={guided_without:.3f} -> with={guided_with:.3f} "
          f"(lift +{guided_with - guided_without:.3f})\n"
          f"  UNGUIDED (n={u_n:,}): without={unguided_without:.3f} -> with={unguided_with:.3f} "
          f"(lift {unguided_with - unguided_without:+.3f})\n"
          + "".join(f"  {r:10} promote={promo[r][0] / max(1, promo[r][1]):.3f} "
                    f"({promo[r][1]:,} passes)\n" for r in sorted(USEFUL | TRAP)))

    assert done >= trials * 0.99
    assert g_n > trials * 0.1, f"too few guided trials: {g_n}"
    assert guided_with - guided_without > 0.5, f"no lift: {guided_without} -> {guided_with}"
    assert guided_with > 0.8 and guided_without < 0.25
    assert abs(unguided_with - unguided_without) < 0.02, "spurious lift on unguided work"
    assert useful_rate > 0.99, f"useful guidance under-promoted: {useful_rate}"
    assert trap_rate < 0.01, f"a trap (useless/overfit/distractor) was promoted: {trap_rate}"
