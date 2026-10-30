"""The ``xp`` tool on the fake platform: requests as intents, credits, the ask-above setting,
status with download, evaluate and stored rows, a broken evaluate, a backgrounded evaluate."""

from __future__ import annotations

import json
import textwrap
import time

import pytest

import research_core.tools.xp as xp_tool
from research_core.platform import fake
from research_core.store import (
    capabilities,
    experiments,
    goals,
    intents,
    sessions,
    settings,
    tasks,
    versions,
)
from research_core.store.actors import Actor
from research_core.tools.base import ToolContext, run_tool
from tests.fixtures.fakegame_repo import fixture_files

N_MIN = 2
HYPOTHESIS = {
    "statement": "More patience wins more",
    "if_true": "score rises",
    "if_false": "score stays within noise",
    "motivation": "patience is untested",
}
METRICS = [
    {"name": "score", "direction": "up", "role": "primary", "min_effect": 1.0},
    {"name": "errors", "direction": "down", "role": "guardrail", "tolerance": 1.0},
]
# The fixture's evaluate.py takes the results folder on its command line and prints a
# ``source`` key that ``ingest.rows_from_evaluate_output`` refuses (unknown keys), so the test
# mixin passes ``$XP_RESULTS`` and pipes the rows through a filter that drops the key.
EVALUATE_COMMAND = (
    'python3 mixin/tools/evaluate.py "$XP_RESULTS" | python3 mixin/tools/rows_only.py'
)
ROWS_ONLY = textwrap.dedent(
    """\
    import json, sys
    for line in sys.stdin:
        if line.strip():
            row = json.loads(line)
            row.pop("source", None)
            print(json.dumps(row, sort_keys=True))
    """
)


def policy_bytes(aggression: int, patience: int) -> bytes:
    return json.dumps({"parameters": {"aggression": aggression, "patience": patience}}).encode()


@pytest.fixture
def run(ctx_factory, workspace_env):
    """``run(tool, args, role=, session_id=, faults=)``: a tool call with fake-platform faults."""
    ctx_factory()  # registers and activates cow_fake

    def call(tool, args, *, role="orchestrator", session_id="s1", faults=""):
        env = dict(workspace_env, IDE_SESSION_ID=session_id, IDE_FAKE_FAULTS=faults)
        return json.loads(run_tool(tool, args, ToolContext.from_env(role, env)))

    return call


@pytest.fixture
def ctx(ctx_factory):
    return ctx_factory()


@pytest.fixture
def mixin_dir(ctx):
    """The fakegame mixin at ``<coworld>/code/mixin`` with the test's evaluate command."""
    code = ctx.coworld().code
    for relative, content in fixture_files(fake.COWORLD_ID).items():
        path = code / "mixin" / relative
        path.parent.mkdir(parents=True, exist_ok=True)
        path.write_text(content, encoding="utf-8")
    set_evaluate_command(code / "mixin", EVALUATE_COMMAND)
    (code / "mixin" / "tools" / "rows_only.py").write_text(ROWS_ONLY)
    return code / "mixin"


def set_evaluate_command(mixin_dir, command: str) -> None:
    text = (mixin_dir / "MIXIN.md").read_text()
    head, sep, tail = text.partition("\n---\n")
    lines = [
        f"  evaluate: {json.dumps(command)}" if line.startswith("  evaluate:") else line
        for line in head.splitlines()
    ]
    (mixin_dir / "MIXIN.md").write_text("\n".join(lines) + sep + tail)


@pytest.fixture
def uploaded(ctx):
    """V-1 (baseline) and V-2 (candidate), built and uploaded through the fake platform."""
    platform = ctx.platform()
    for n, patience in ((1, 5), (2, 8)):
        versions.create(
            ctx.store,
            ctx.actor,
            summary=f"policy {n}",
            commit_sha=f"{n:040x}",
            branch="main",
            artifact={"kind": "file", "path": "build/policy.json", "digest": "d" * 64, "size": 1},
            based_on=[],
        )
        pv = platform.upload_file_policy(name=f"policy-{n}", content=policy_bytes(3, patience))
        versions.mark_uploaded(
            ctx.store, ctx.actor, n, policy_version_id=pv.id, at=pv.created_at, digest_checked=True
        )


def make_experiment(ctx, *, start=True, task_id=None, n_min=N_MIN) -> dict:
    record = experiments.create(
        ctx.store,
        ctx.actor,
        summary="Does patience raise the score?",
        task_id=task_id,
        hypothesis=HYPOTHESIS,
        methods={
            "baseline": "V-1",
            "candidate": "V-2",
            "procedure": "one episode per seed per arm",
            "metrics": METRICS,
            "decision_rule": {"text": "score up by 1 with the CI above zero", "n_min": n_min},
        },
    )
    if start:
        record = experiments.start(ctx.store, ctx.actor, record["id"])
    return record


@pytest.fixture
def running(ctx, uploaded):
    return make_experiment(ctx)


def xp_runs(ctx, n=1):
    return [r for r in experiments.read(ctx.store, n)["runs"] if r["kind"] == "xp"]


def wait_for_rows(run, token, *, timeout=20):
    deadline = time.time() + timeout
    while True:
        result = run("xp", {"action": "status", "resume": token})
        if "background" not in result:
            return result
        assert time.time() < deadline, "evaluate did not finish in time"
        time.sleep(0.1)


# --- request ---------------------------------------------------------------------------------


def test_request_creates_one_request_per_seed_and_arm(run, ctx, running):
    result = run("xp", {"action": "request", "experiment": "X-1"})
    assert result["ok"] is True, result
    assert len(result["created"]) == 4 and result["reconciled"] == []
    runs = result["runs"]
    assert [(r["seed"], r["arm"]) for r in runs] == [
        (1, "candidate"),
        (1, "baseline"),
        (2, "candidate"),
        (2, "baseline"),
    ]
    assert all(r["state"] == "pending" and r["episodes_total"] == 1 for r in runs)
    assert runs[0]["results"]["version"] == "V-2" and runs[1]["results"]["version"] == "V-1"
    assert runs[0]["results"]["title"] == "ide:X-1:1:candidate"
    titles = sorted(r.title for r in ctx.platform().xp_list())
    assert titles == sorted(f"ide:X-1:{seed}:{arm}" for seed in (1, 2) for arm in xp_tool.ARMS)
    assert ctx.platform().snapshot()["counts"]["xp_create"] == 4
    assert result["credits"].startswith("credits: 96 available of 100")
    assert result["estimate"] == {"episodes": 4, "credits": 4.0}
    assert result["warnings"] == []
    assert "xp.status" in result["next"]
    assert [i["state"] for i in (intents.read(ctx.store, n) for n in range(1, 5))] == ["done"] * 4

    again = run("xp", {"action": "request", "experiment": "X-1"})
    assert again["ok"] is True and again["created"] == [] and len(again["runs"]) == 4
    assert ctx.platform().snapshot()["counts"]["xp_create"] == 4


def test_request_body_and_options(run, ctx, running):
    result = run(
        "xp",
        {
            "action": "request",
            "experiment": 1,
            "seeds": [7],
            "episodes": 3,
            "arms": ["candidate"],
            "league": fake.LEAGUE_ID,
            "opponents": ["pv_other"],
        },
    )
    assert result["ok"] is True, result
    (row,) = ctx.platform().snapshot()["xp"].values()
    assert row["body"] == {
        "coworld_id": fake.COWORLD_ID,
        "roster": [
            {"player": {"policy_ref": row["policy"]}, "slot": 0},
            {"player": {"policy_ref": "pv_other"}, "slot": 1},
        ],
        "num_episodes": 3,
        "title": "ide:X-1:7:candidate",
        "target": {"league_id": fake.LEAGUE_ID},
        "game_config_overrides": {"seed": 7},
    }
    assert result["runs"][0]["episodes_total"] == 3
    assert any("below the decision rule's n_min" in w for w in result["warnings"])


def test_request_refusals_name_every_problem(run, ctx, uploaded):
    proposed = make_experiment(ctx, start=False)
    result = run("xp", {"action": "request", "experiment": proposed["id"], "seeds": [1, 1]})
    assert result["ok"] is False
    assert "X-1 is proposed; start the experiment first (experiment.start)" in result["problems"]
    assert "seeds must not repeat" in result["problems"]

    other = run("xp", {"action": "request", "experiment": "X-1", "candidate": "V-1"})
    assert (
        "candidate V-1 differs from X-1's locked methods.candidate V-2; abandon X-1 and create a"
        " new Experiment to test another Version"
    ) in other["problems"]

    versions.create(
        ctx.store,
        ctx.actor,
        summary="not uploaded",
        commit_sha="3" * 40,
        branch="main",
        artifact={"kind": "file", "path": "build/policy.json", "digest": "e" * 64, "size": 1},
        based_on=[],
    )
    record = experiments.create(
        ctx.store,
        ctx.actor,
        summary="Second",
        hypothesis=HYPOTHESIS,
        methods={**proposed["methods"], "candidate": "V-3"},
    )
    experiments.start(ctx.store, ctx.actor, record["id"])
    result = run("xp", {"action": "request", "experiment": record["id"]})
    assert result["ok"] is False
    assert "V-3 (candidate) is not uploaded; run upload {version: V-3} first" in result["problems"]
    assert ctx.platform().snapshot()["counts"]["xp_create"] == 0


def test_request_is_idempotent_after_a_crash_between_create_and_record(run, ctx, running):
    crashed = run("xp", {"action": "request", "experiment": "X-1"}, faults="fail_after=xp_create")
    assert crashed["ok"] is False and "injected fault after xp_create" in crashed["error"]
    platform = ctx.platform()
    assert platform.snapshot()["counts"]["xp_create"] == 1
    assert xp_runs(ctx) == []
    (pending,) = intents.pending(ctx.store, "xp")
    assert pending["key"] == "X-1:1:candidate"

    result = run("xp", {"action": "request", "experiment": "X-1"})
    assert result["ok"] is True, result
    assert platform.snapshot()["counts"]["xp_create"] == 4
    assert len(result["reconciled"]) == 1 and len(result["created"]) == 3
    assert [r.title for r in platform.xp_list() if r.id == result["reconciled"][0]] == [
        "ide:X-1:1:candidate"
    ]
    assert len(xp_runs(ctx)) == 4 and intents.pending(ctx.store, "xp") == []


@pytest.fixture
def researcher_task(ctx):
    """A Researcher task Session ``r1`` holding T-1, and X-1 as that Task's Experiment."""
    goal = goals.create(ctx.store, ctx.actor, title="g", end_state="e", reason="r")
    task = tasks.create(
        ctx.store, ctx.actor, type="improvement", title="t", description="d", goal_id=goal["id"]
    )
    holder = Actor.session("r1")
    tasks.claim(ctx.store, holder, task["id"], run_id="run-1", worktree="/w/task-1", branch="t/1")
    sessions.register(
        ctx.wstore, holder, session_id="r1", profile="researcher", kind="task", task_id=1
    )
    return task


def test_credits_refusal_reports_the_balance_and_sets_no_wait(run, ctx, uploaded, researcher_task):
    make_experiment(ctx, task_id=1)
    result = run(
        "xp",
        {"action": "request", "experiment": "X-1"},
        role="researcher",
        session_id="r1",
        faults="credits_refuse=1",
    )
    assert result["ok"] is False
    assert result["credits_refused"]["balance"] == 100.0
    assert result["credits_refused"]["held"] == 0.0
    assert result["credits_refused"]["next_refill_at"]
    assert "task.wait {kind: credits" in result["next"]
    assert result["created"] == [] and result["runs"] == []
    assert tasks.read(ctx.store, 1)["waiting_on"] is None
    intent = intents.read(ctx.store, 1)
    assert intent["state"] == "failed" and intent["result"]["status"] == 402
    assert ctx.platform().snapshot()["counts"]["xp_create"] == 0

    retried = run(
        "xp", {"action": "request", "experiment": "X-1"}, role="researcher", session_id="r1"
    )
    assert retried["ok"] is True, retried
    assert (
        intents.read(ctx.store, 1)["state"] == "done" and intents.read(ctx.store, 1)["attempt"] == 2
    )
    assert "task.wait {kind: xp, ref: [" in retried["next"]
    assert tasks.read(ctx.store, 1)["waiting_on"] is None


def test_ask_above_warns_the_orchestrator_and_asks_the_researcher(run, ctx, uploaded):
    make_experiment(ctx)
    settings.update(ctx.store, ctx.actor, xp_tool.ASK_ABOVE_KEY, 2, cites="the user said so")
    researcher = run("xp", {"action": "request", "experiment": "X-1"}, role="researcher")
    assert researcher["ok"] is False and researcher["ask_orchestrator"] is True
    assert researcher["counts"] == {"existing": 0, "new": 4, "total": 4, "limit": 2}
    assert researcher["suggest"].startswith("task.ask {task: <your Task>, question: ")
    assert ctx.platform().snapshot()["counts"]["xp_create"] == 0

    orchestrator = run("xp", {"action": "request", "experiment": "X-1"})
    assert orchestrator["ok"] is True, orchestrator
    assert len(orchestrator["created"]) == 4
    (warning,) = orchestrator["warnings"]
    assert "4 XP requests, above the xp.ask_above_requests_per_experiment setting of 2" in warning


def test_tool_spec(run):
    spec = xp_tool.SPEC
    assert spec.executor == "workspace" and spec.roles == {"orchestrator", "researcher"}
    assert [action.name for action in spec.actions] == ["request", "status"]
    assert {action.name for action in spec.actions_for("researcher")} == {"request", "status"}
    missing = run("xp", {"action": "status"})
    assert missing["ok"] is False and "needs an experiment" in missing["error"]


# --- status ----------------------------------------------------------------------------------


def test_status_completes_downloads_evaluates_and_stores_rows(run, ctx, running, mixin_dir):
    ctx.platform().configure(polls_to_complete=2)
    requested = run("xp", {"action": "request", "experiment": "X-1", "seeds": [1]})
    assert requested["ok"] is True, requested
    first = run("xp", {"action": "status", "experiment": "X-1"})
    assert first["ok"] is True and first["complete"] is False
    assert len(first["pending"]) == 2
    assert all(r["state"] == "running" for r in first["runs"])

    second = run("xp", {"action": "status", "experiment": "X-1"})
    assert second["ok"] is True, second
    assert second["complete"] is True and second["pending"] == []
    assert "experiment.close" in second["next"]
    by_arm = {r["arm"]: r for r in second["runs"]}
    for arm, version in (("candidate", "V-2"), ("baseline", "V-1")):
        run_record = by_arm[arm]
        assert run_record["state"] == "completed" and run_record["validity"] == "valid"
        assert run_record["episodes_completed"] == 1
        request_id = run_record["platform_request_id"]
        rows = run_record["results"]["rows"]
        assert len(rows) == 1
        assert rows[0] == {
            "episode_id": f"{request_id}:0:s0",
            "game_version": "1",
            "policy_version": version,
            "seed": 1,
            "seats": [0],
            "opponents": [],
            "metrics": {
                "score": rows[0]["metrics"]["score"],
                "errors": rows[0]["metrics"]["errors"],
            },
            "status": "completed",
            "reason": None,
        }
        assert run_record["results"]["evaluate"]["exit_code"] == 0
        dest = ctx.coworld().documents / "xp" / "X-1" / request_id
        assert (dest / "results.json").is_file()
    assert (
        by_arm["candidate"]["results"]["rows"][0]["metrics"]
        != by_arm["baseline"]["results"]["rows"][0]["metrics"]
    )
    # Stored rows rebuild as EpisodeRow through the experiment tool's contract.
    from research_core.tools.experiment import row_from_dict

    assert row_from_dict(by_arm["candidate"]["results"]["rows"][0]).policy_version == "V-2"

    third = run("xp", {"action": "status", "request": by_arm["baseline"]["platform_request_id"]})
    assert third["complete"] is True and len(third["runs"]) == 2


def test_status_marks_a_broken_evaluate_invalid_and_reports_the_capability(
    run, ctx, running, mixin_dir
):
    set_evaluate_command(mixin_dir, "false")
    run("xp", {"action": "request", "experiment": "X-1", "seeds": [1], "arms": ["candidate"]})
    result = run("xp", {"action": "status", "experiment": "X-1"})
    assert result["ok"] is True, result
    (run_record,) = result["runs"]
    assert run_record["validity"] == "invalid: evaluate failed (exit 1)"
    assert "rows" not in run_record["results"]
    assert result["complete"] is True
    broken = capabilities.read(ctx.store, "evaluate")
    assert broken["status"] == "broken" and broken["command"] == "false"
    assert tasks.read(ctx.store, broken["maintenance_task_id"])["capability"] == "evaluate"

    set_evaluate_command(mixin_dir, "echo not-json")
    run("xp", {"action": "request", "experiment": "X-1", "seeds": [2], "arms": ["candidate"]})
    result = run("xp", {"action": "status", "experiment": "X-1"})
    second = [r for r in result["runs"] if r["seed"] == 2][0]
    assert second["validity"].startswith("invalid: evaluate output: evaluate output line 1")


def test_status_backgrounds_a_slow_evaluate_and_resumes(run, ctx, running, mixin_dir, monkeypatch):
    monkeypatch.setattr(xp_tool, "EVALUATE_BUDGET_S", 0.2)
    set_evaluate_command(mixin_dir, f"sleep 1; {EVALUATE_COMMAND}")
    run("xp", {"action": "request", "experiment": "X-1", "seeds": [1], "arms": ["baseline"]})
    started = run("xp", {"action": "status", "experiment": "X-1"})
    assert started["ok"] is True and started["background"]["pid"] > 0
    assert "task.wait {kind: process" in started["next"]
    token = started["background"]["resume"]
    assert "rows" not in xp_runs(ctx)[0]["results"]

    finished = wait_for_rows(run, token)
    assert finished["ok"] is True, finished
    assert finished["complete"] is True
    (run_record,) = finished["runs"]
    assert len(run_record["results"]["rows"]) == 1 and run_record["validity"] == "valid"
    # The same token again is a no-op: the rows are already stored.
    assert run("xp", {"action": "status", "resume": token})["complete"] is True


def test_status_on_a_closed_experiment_reports_without_touching_runs(run, ctx, running):
    run("xp", {"action": "request", "experiment": "X-1", "seeds": [1], "arms": ["baseline"]})
    experiments.abandon(ctx.store, ctx.actor, "X-1", reason="moot")
    result = run("xp", {"action": "status", "experiment": "X-1"})
    assert result["ok"] is True and result["note"] == "X-1 is abandoned; its runs are final"
    assert result["runs"][0]["state"] == "pending"
