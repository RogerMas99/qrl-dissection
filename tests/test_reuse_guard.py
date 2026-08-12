import pathlib
"""A finished cell may only be reused if it answers the same question.

This exists because it did not hold. `run_name` encodes arm, FIX-01 state, seed
and tag - readable, and an incomplete key. A 1,500-step smoke cell and a
100,000-step production cell get the same filename, so the old
`if manifest.exists(): skip` reported the smoke numbers as the production run,
with different batch size and buffer size, and printed nothing.

That is the worst class of bug this repository can have: not a crash, but a
plausible number attached to the wrong experiment. Hence a guard, and hence a
test for the guard.
"""
import json

import pytest

from qrl_dissection.dqn.runner import REUSE_KEYS, reuse_or_none


def _write(tmp_path, name, spec, env_id="CartPole-v1"):
    p = tmp_path / f"{name}.manifest.json"
    p.write_text(json.dumps({"spec": spec, "run_name": name, "env_id": env_id,
                             "outcome": {}}))
    return p


BASE = {"arm": "hybrid_fig4", "seed": 1, "fix_autoreset": True,
        "total_timesteps": 100_000, "dqn_kwargs": {"batch_size": 128}, "tag": ""}


def test_missing_manifest_is_not_a_hit(tmp_path):
    assert reuse_or_none(tmp_path / "nope.manifest.json", BASE) is None


def test_identical_spec_is_reused(tmp_path):
    p = _write(tmp_path, "run", BASE)
    assert reuse_or_none(p, dict(BASE)) is not None


def test_shorter_run_does_not_satisfy_a_longer_request(tmp_path):
    """The original bug, verbatim."""
    p = _write(tmp_path, "run", dict(BASE, total_timesteps=1_500))
    with pytest.raises(RuntimeError, match="total_timesteps"):
        reuse_or_none(p, BASE)


def test_longer_run_does_not_silently_satisfy_a_shorter_one_either(tmp_path):
    """Deliberately symmetric. A 100k run is not a 60k run: every metric here is
    computed over the whole trace, so the extra steps change the answer."""
    p = _write(tmp_path, "run", dict(BASE, total_timesteps=1_000_000))
    with pytest.raises(RuntimeError, match="total_timesteps"):
        reuse_or_none(p, BASE)


@pytest.mark.parametrize("field,value", [
    ("arm", "oversized_mlp"),
    ("seed", 7),
    ("fix_autoreset", False),
    ("dqn_kwargs", {"batch_size": 32}),
    ("tag", "v2"),
])
def test_every_material_field_is_compared(field, value, tmp_path):
    p = _write(tmp_path, "run", dict(BASE, **{field: value}))
    with pytest.raises(RuntimeError, match=field):
        reuse_or_none(p, BASE)


def test_environment_mismatch_is_caught(tmp_path):
    """exp04 runs two arms on two different registered ids in one grid."""
    p = _write(tmp_path, "run", BASE, env_id="FrozenLake4x4OneHot-v0")
    with pytest.raises(RuntimeError, match="env_id"):
        reuse_or_none(p, BASE, env_id="FrozenLake4x4Scalar-v0")


def test_rerun_mode_returns_none_instead_of_raising(tmp_path):
    p = _write(tmp_path, "run", dict(BASE, total_timesteps=1_500))
    assert reuse_or_none(p, BASE, on_mismatch="rerun") is None


def test_skip_mode_reuses_anyway(tmp_path):
    """Escape hatch for reading old results deliberately. Never a default."""
    p = _write(tmp_path, "run", dict(BASE, total_timesteps=1_500))
    assert reuse_or_none(p, BASE, on_mismatch="skip") is not None


def test_absent_keys_are_not_compared(tmp_path):
    """Scripts that roll their own run_one pass a partial spec; they should be
    able to check the fields they know without being punished for the rest."""
    p = _write(tmp_path, "run", BASE)
    assert reuse_or_none(p, {"seed": 1, "total_timesteps": 100_000}) is not None


def test_reuse_keys_cover_what_defines_a_run():
    for key in ("arm", "seed", "fix_autoreset", "total_timesteps", "dqn_kwargs", "tag"):
        assert key in REUSE_KEYS


# ---------------------------------------------------------------------------
# Legacy manifests. Early scripts wrote {name, seed, fix_autoreset, outcome,
# config} and nothing else. Absence of a field is not evidence of a mismatch,
# so refusing outright would recompute hours of finished simulation - but
# accepting silently is how FIX-08 happened. Hence a third outcome.
# ---------------------------------------------------------------------------

LEGACY = {"name": "hybrid_DR5__s1", "seed": 1, "fix_autoreset": True,
          "outcome": {"total_timesteps": 100_000}, "config": {}}


def _write_raw(tmp_path, name, payload):
    p = tmp_path / f"{name}.manifest.json"
    p.write_text(json.dumps(payload))
    return p


def test_legacy_manifest_raises_a_different_error(tmp_path):
    """It must not be confused with a real mismatch: the remedy differs."""
    p = _write_raw(tmp_path, "run", LEGACY)
    with pytest.raises(RuntimeError, match="LEGACY"):
        reuse_or_none(p, {"seed": 1, "dqn_kwargs": {"batch_size": 128}})


def test_legacy_mode_accepts_it(tmp_path):
    p = _write_raw(tmp_path, "run", LEGACY)
    assert reuse_or_none(p, {"seed": 1, "dqn_kwargs": {"batch_size": 128}},
                         on_mismatch="legacy") is not None


def test_step_budget_is_recovered_from_the_outcome(tmp_path):
    """The one field that IS recoverable from a legacy manifest, so a genuine
    step-budget mismatch is still caught rather than excused as legacy."""
    p = _write_raw(tmp_path, "run", LEGACY)
    assert reuse_or_none(p, {"seed": 1, "total_timesteps": 100_000}) is not None
    with pytest.raises(RuntimeError, match="total_timesteps"):
        reuse_or_none(p, {"seed": 1, "total_timesteps": 60_000})


def test_a_real_mismatch_beats_a_legacy_gap(tmp_path):
    """If one field contradicts and another is merely absent, report the
    contradiction: it is the one that would corrupt a result."""
    p = _write_raw(tmp_path, "run", LEGACY)
    with pytest.raises(RuntimeError, match="total_timesteps"):
        reuse_or_none(p, {"seed": 1, "total_timesteps": 60_000,
                          "dqn_kwargs": {"batch_size": 128}})


# ---------------------------------------------------------------------------
# Cooperative claiming across parallel sessions.
# ---------------------------------------------------------------------------

def test_claim_is_exclusive_then_released(tmp_path):
    from qrl_dissection.dqn.runner import claim_cell, release_cell
    mp = tmp_path / "run.manifest.json"
    assert claim_cell(mp, owner="A") is True
    assert claim_cell(mp, owner="B") is False, "two sessions must not hold one cell"
    release_cell(mp)
    assert claim_cell(mp, owner="B") is True, "released cell must be claimable"


def test_stale_claims_are_reclaimed(tmp_path):
    """A session that dies must not reserve a cell forever - with multi-hour
    cells and flaky Colab runtimes, that would strand work indefinitely."""
    import json as _json
    import time as _time
    from qrl_dissection.dqn.runner import _lock_path, claim_cell

    mp = tmp_path / "run.manifest.json"
    _lock_path(mp).write_text(_json.dumps({"owner": "dead", "t": _time.time() - 3600 * 30}))
    assert claim_cell(mp, ttl_hours=12, owner="B") is True


def test_fresh_claims_are_respected(tmp_path):
    import json as _json
    import time as _time
    from qrl_dissection.dqn.runner import _lock_path, claim_cell

    mp = tmp_path / "run.manifest.json"
    _lock_path(mp).write_text(_json.dumps({"owner": "alive", "t": _time.time()}))
    assert claim_cell(mp, ttl_hours=12, owner="B") is False


def test_unreadable_lock_is_treated_as_stale(tmp_path):
    """Drive can leave a partial file. Refusing forever on garbage would be worse
    than the duplicated compute of claiming it."""
    from qrl_dissection.dqn.runner import _lock_path, claim_cell

    mp = tmp_path / "run.manifest.json"
    _lock_path(mp).write_text("{not json")
    assert claim_cell(mp, owner="B") is True


def test_exp04_wires_claim_into_run_grid_not_eval_cfg():
    """Regression for a real bug: --claim was passed to eval_cfg_for(), which
    builds a GreedyEvalConfig and has no use for it, instead of to run_grid(),
    which is what actually needs it to lock cells. Caught the first time exp04
    was run with --claim: TypeError, eval_cfg_for() got an unexpected keyword
    argument 'claim'."""
    src = pathlib.Path("experiments/exp04_dqn_frozenlake_embeddings.py").read_text()
    assert "eval_cfg_for(env_id, args.eval_every, claim=" not in src
    assert "eval_cfg_for(FROZEN_SCALAR_ID, args.eval_every, claim=" not in src
    assert src.count("claim=args.claim") == 2, (
        "expected exactly the two run_grid() calls (stage 1 and stage 2) to "
        "receive claim=args.claim"
    )


def test_exp02_manifest_writer_records_the_fields_the_guard_checks():
    """Regression for a real bug. exp02's run_one wrote a manifest without
    total_timesteps or dqn_kwargs, so any cell it produced was legacy the
    instant it was created - a cell could finish successfully overnight and
    still be rejected as unverifiable the next morning. exp03 and exp03b never
    had this bug; only exp02 did. Reproduced directly with hybrid_OR4__s4."""
    src = pathlib.Path("experiments/exp02_dqn_cartpole_output_reuse.py").read_text()
    block = src[src.index('m = {"name": name, "agent_type"'):]
    block = block[:block.index("manifest.write_text")]
    assert '"total_timesteps": steps' in block
    assert '"dqn_kwargs": kw' in block
