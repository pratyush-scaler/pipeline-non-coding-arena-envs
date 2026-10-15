"""Calibration against the spec's own terms (C1-C4, A3, A4/B2).

Every test here fails on the code it replaced:

  - a missing primary model became a "deviation" that applied pass@1 to
    whichever model sorted first; effort and limits were only compared with
    each other, never with policy; retired names were matched case-sensitively
    and no launcher refused one
  - the contract verdict was unreachable (read `band_declared`, the generator
    writes `band`), the grader's own `contract_errors` were never read, and an
    episode with no failed check was a pass whatever its reward
  - native rows never carried `misses`, so the near-miss obligation was inert
  - no calibration trajectory was ever read for reward hacking, and one planted
    symlink made a whole campaign unreadable
  - `hardness(P, None)` reported the spec's general difficulty met
"""
import inspect
import json
import os
import shutil
import tempfile
import unittest
from contextlib import ExitStack
from pathlib import Path
from unittest.mock import patch

from pipeline import attribution, evidence, metrics, policy, release
from pipeline.artifacts import atomic_json, evidence_inventory, identity
from pipeline.benchmark import harbor
from pipeline.benchmark.harbor import PROTOCOL
from pipeline.tests.test_production import synthetic_bundle

PRIMARY = "anthropic/" + policy.SPEC_PRIMARY_MODEL
SECONDARY = "openai/" + policy.SPEC_SECONDARY_MODEL


def _rows(rewards, step="01-task"):
    return [{"episode": e, "step": step, "id": f"t{e}/{step}", "reward": r,
             "zero_class": None, "error": None, "stop_reason": "completed",
             "tool_calls": 3, "checks": {}} for e, r in enumerate(rewards, 1)]


def _measured(model, rewards, effort=policy.SPEC_CALIBRATION_EFFORT,
              no_limits=policy.SPEC_NO_LIMITS):
    return {"model": model, "effort": effort, "protocol": PROTOCOL,
            "limits": {"no_limits": no_limits, "context_limit": None,
                       "campaign_timeout_sec": None,
                       "max_output_tokens": policy.output_tokens_for(model)},
            "step_names": ["01-task"], "rollouts": _rows(rewards), "trials": [],
            "by_step": {}}


class RetiredModelsAreRefusedAtLaunch(unittest.TestCase):

    def test_retired_names_match_case_insensitively(self):
        for name in ("Claude-Opus-5", "anthropic/CLAUDE-OPUS-5", "openai/GPT-5.6-Sol"):
            self.assertTrue(policy.calibration_problems([name]), name)
        self.assertEqual(policy.calibration_problems([PRIMARY, SECONDARY]), [])

    def test_harbor_refuses_a_retired_model_before_staging_anything(self):
        with tempfile.TemporaryDirectory() as tmp, \
                patch.object(harbor, "inspect_package") as inspect_package:
            with self.assertRaisesRegex(ValueError, "retired"):
                harbor.run_campaign(Path(tmp) / "b", Path(tmp) / "out",
                                    model="Anthropic/Claude-Opus-5", dry_run=True)
            inspect_package.assert_not_called()
            self.assertFalse((Path(tmp) / "out").exists())

    def test_the_file_workspace_campaign_refuses_one_too(self):
        # Presolve reaches the solver through this function.
        from pipeline.calibrate import run
        with patch("pipeline.artifacts.freeze") as freeze:
            with self.assertRaisesRegex(ValueError, "retired"):
                run.campaign(Path("/nonexistent"), "gpt-5.6-sol", n=1)
            freeze.assert_not_called()

    def test_harbor_defaults_are_the_policy_measurement(self):
        params = inspect.signature(harbor.run_campaign).parameters
        self.assertEqual(params["effort"].default, policy.SPEC_CALIBRATION_EFFORT)
        self.assertIs(params["no_limits"].default, policy.SPEC_NO_LIMITS)

    def test_default_campaign_runs_uncapped_and_without_a_deadline(self):
        info = {"step_names": ["01-task"], "multi_step_reward_strategy": None}
        with tempfile.TemporaryDirectory() as tmp, ExitStack() as stack:
            for name, value in (("inspect_package", info),
                                ("fingerprint", {"sha256": "x"}),
                                ("file_modes", {"sha256": "y"}),
                                ("_stage_lifecycle", {}),
                                ("_history_adapter", {"files": [], "pythonpath": ""})):
                stack.enter_context(patch.object(harbor, name, return_value=value))
            stack.enter_context(patch.object(harbor, "copy_tree"))
            stack.enter_context(patch("pipeline.benchmark.preflight.validate_task",
                                      return_value={}))
            root = Path(tmp).resolve()                 # macOS: /var is a symlink
            (root / "b").mkdir()
            report = harbor.run_campaign(root / "b", root / "out",
                                         model=policy.SPEC_PRIMARY_MODEL, dry_run=True)
        self.assertEqual(report["effort"], policy.SPEC_CALIBRATION_EFFORT)
        self.assertIs(report["limits"]["no_limits"], True)
        self.assertIsNone(report["limits"]["campaign_timeout_sec"])


class ReleaseDemandsTheSpecModelSet(unittest.TestCase):

    @classmethod
    def setUpClass(cls):
        cls._tmp = tempfile.TemporaryDirectory()
        cls.bundle = synthetic_bundle(Path(cls._tmp.name).resolve())

    @classmethod
    def tearDownClass(cls):
        cls._tmp.cleanup()

    def evaluate(self, *measured, hacks=None):
        by_path = {f"/c/{i}": m for i, m in enumerate(measured)}
        atomic_json(self.bundle / "verification/native-calibrations.json",
                    {"artifact_sha256": identity(self.bundle), "campaigns": list(by_path)})
        with ExitStack() as stack:
            stack.enter_context(patch.object(
                release, "calibration_measurement",
                side_effect=lambda b, i, path, n: ([], by_path[path])))
            stack.enter_context(patch.object(attribution, "problems", return_value=[]))
            stack.enter_context(patch.object(
                attribution, "trajectory_hacks", create=True,
                side_effect=lambda b, m: (hacks or {}).get(m.get("model"), [])))
            report = release._evaluate(self.bundle)
        return ([e for e in report["errors"] if e.startswith("calibration:")],
                report["evidence"])

    def test_the_spec_set_measured_as_specified_is_clean(self):
        errors, ev = self.evaluate(_measured(PRIMARY, [1.0] * 3 + [0.0] * 7),
                                   _measured(SECONDARY, [1.0] * 2 + [0.0] * 8))
        self.assertEqual(errors, [])
        self.assertTrue(ev["meets_spec_general_difficulty"])
        self.assertAlmostEqual(ev["hardness"]["primary_pass_at_1"], 0.3)

    def test_a_missing_primary_blocks_instead_of_becoming_a_deviation(self):
        errors, ev = self.evaluate(_measured("anthropic/claude-sonnet-9", [0.0] * 10),
                                   _measured(SECONDARY, [0.0] * 10))
        self.assertTrue(any("not the spec's set" in e and PRIMARY in e for e in errors), errors)
        self.assertNotIn("deviations", ev)
        self.assertIsNone(ev["hardness"]["primary_pass_at_1"])
        self.assertFalse(ev["meets_spec_general_difficulty"])

    def test_effort_and_limits_must_equal_policy_not_just_each_other(self):
        errors, _ = self.evaluate(_measured(PRIMARY, [0.0] * 10, effort="medium"),
                                  _measured(SECONDARY, [0.0] * 10, effort="medium"))
        self.assertTrue(any("reasoning effort 'medium'" in e for e in errors), errors)
        errors, _ = self.evaluate(_measured(PRIMARY, [0.0] * 10, no_limits=False),
                                  _measured(SECONDARY, [0.0] * 10, no_limits=False))
        self.assertTrue(any("limits.no_limits is False" in e for e in errors), errors)

    def test_a_retired_model_in_another_case_blocks(self):
        errors, _ = self.evaluate(_measured(PRIMARY, [0.0] * 10),
                                  _measured(SECONDARY, [0.0] * 10),
                                  _measured("anthropic/Claude-Opus-5", [0.0] * 10))
        self.assertTrue(any("superseded" in e for e in errors), errors)

    def test_an_easy_valid_task_is_admitted_but_labelled_outside_the_target(self):
        errors, ev = self.evaluate(_measured(PRIMARY, [1.0] * 5 + [0.0] * 5),
                                   _measured(SECONDARY, [1.0] * 5 + [0.0] * 5))
        self.assertEqual(errors, [])
        # User 2026-10-02: pass@1 <= 0.5 is hard, so exactly 0.5 meets the target.
        self.assertTrue(ev["meets_spec_general_difficulty"])
        self.assertFalse(ev["hardness"]["meets_release_bound"])

    def test_a_reward_hack_blocks_and_names_the_trial(self):
        hit = {"trial": "package__abc", "step": "01-task", "kind": "test_access",
               "evidence": "turn 3: cat /tests/checks.json"}
        errors, ev = self.evaluate(_measured(PRIMARY, [1.0] * 10),
                                   _measured(SECONDARY, [0.0] * 10),
                                   hacks={PRIMARY: [hit]})
        self.assertTrue(any("package__abc/01-task: test_access" in e for e in errors), errors)
        self.assertIn(hit, ev["reward_hacking"]["/c/0"]["hits"])


class HardnessNeedsBothModels(unittest.TestCase):

    def test_a_missing_secondary_does_not_meet_the_spec(self):
        primary = metrics.task_metrics({"model": "m", "step_names": ["01-task"],
                                        "rollouts": _rows([0.0] * 10)})
        verdict = metrics.hardness(primary, None)
        self.assertFalse(verdict["meets_spec_general_difficulty"])
        self.assertFalse(verdict["meets_release_bound"])
        self.assertTrue(verdict["hard"])                  # defined on the primary alone
        self.assertTrue(metrics.hardness(primary, primary)["meets_spec_general_difficulty"])


def _bundle(root: Path, checks) -> Path:
    atomic_json(root / "tests/checks.json", {"checks": checks})
    atomic_json(root / "tests/outputs.json", {"outputs": [
        {"file": "answer.json", "step": "01-task", "schema": {"type": "object"}}]})
    return root


class ContractVerdictIsReachable(unittest.TestCase):

    def row(self, **over):
        row = {"id": "t/01-task", "episode": 1, "step": "01-task", "reward": 1.0,
               "stop_reason": "completed", "tool_calls": 3, "checks": {"a": "passed"}}
        row.update(over)
        return row

    def test_the_grader_contract_errors_make_a_contract_failure(self):
        verdict = attribution.episode_verdict(
            [self.row(reward=0.0, contract_errors=["answer.json: missing"])], set())
        self.assertEqual(verdict["verdict"], "contract")

    def test_no_failed_check_is_a_pass_only_at_full_reward(self):
        self.assertEqual(attribution.episode_verdict([self.row()], set())["verdict"], "pass")
        self.assertEqual(attribution.episode_verdict([self.row(reward=0.5)], set())["verdict"],
                         "unattributed")

    def test_contract_checks_are_read_from_the_band_the_generator_writes(self):
        with tempfile.TemporaryDirectory() as tmp:
            bundle = _bundle(Path(tmp), [
                {"id": "exists", "kind": "objective", "band": "floor", "assertion": "present",
                 "target": None},
                {"id": "scoreboard", "kind": "objective", "band_declared": "floor",
                 "assertion": "equals", "target": {"op": "record"}},
                {"id": "floor_answer", "kind": "objective", "band": "floor",
                 "assertion": "multiset_equals", "target": {"op": "select"}},
                {"id": "g", "kind": "guardrail", "band": "floor", "assertion": "present"}])
            self.assertEqual(attribution.contract_check_ids(bundle), {"exists"})


def _native_trial(folder: Path, grade: dict, values: dict, reward: float) -> dict:
    step_dir = folder / "steps/01-task"
    atomic_json(step_dir / "verifier/arena-grade.json", grade)
    return {"id": folder.name, "valid": True, "reward": reward,
            "result_file": str(folder / "result.json"),
            "steps": [{"name": "01-task", "valid": True, "reward": reward,
                       "evidence_dir": str(step_dir), "errors": [],
                       "agent_result": {"metadata": {"n_episodes": 3}},
                       "checks": {f"reward/{c}": {"value": v, "gated_out": False}
                                  for c, v in values.items()}}]}


class NativeRowsCarryTheGradersDetail(unittest.TestCase):

    def test_a_missing_deliverable_episode_is_contract(self):
        with tempfile.TemporaryDirectory() as tmp:
            bundle = _bundle(Path(tmp) / "b", [{"id": "a", "kind": "objective", "weight": 100,
                                               "band": "core", "step": "01-task"}])
            trial = _native_trial(Path(tmp) / "t1", {
                "reward": 0.0, "contract_errors": ["answer.json: No such file or directory"],
                "checks": {"a": {"passed": False, "target": 5, "actual": None}}}, {"a": 0}, 0.0)
            rows = evidence.rollouts([trial], ["01-task"])
            self.assertEqual(rows[0]["contract_errors"], ["answer.json: No such file or directory"])
            record = attribution.attribute(bundle, {"rollouts": rows, "step_names": ["01-task"]})
        self.assertEqual(record["counts"], {"contract": 1})

    def test_a_near_miss_on_a_record_reaches_the_all_fail_obligation(self):
        target = {"standard": {"correct": 5, "wrong": 12, "pct": 29.4},
                  "combined": {"correct": 14, "wrong": 3, "pct": 82.4},
                  "defense": {"correct": 11, "wrong": 5, "pct": 68.8}}
        actual = json.loads(json.dumps(target))
        actual["combined"]["correct"] = 13
        with tempfile.TemporaryDirectory() as tmp:
            bundle = _bundle(Path(tmp) / "b", [{"id": "a", "kind": "objective", "weight": 100,
                                               "band": "core", "step": "01-task"}])
            trials = [_native_trial(Path(tmp) / f"t{i}", {
                "reward": 0.0, "contract_errors": [],
                "checks": {"a": {"passed": False, "target": target, "actual": actual}}},
                {"a": 0}, 0.0) for i in range(10)]
            rows = evidence.rollouts(trials, ["01-task"])
            self.assertTrue(rows[0]["misses"]["a"].startswith("overlap_0.8"), rows[0]["misses"])
            report = {"rollouts": rows, "by_step": {"01-task": {"checks": {
                "a": {"passed": 0, "failed": 10, "gated_out": 0}}}}}
            problems = attribution.all_fail_problems(bundle, report)
        self.assertTrue(any("unadjudicated near miss" in p for p in problems), problems)


def _hack_trial(root: Path, tid: str, commands, files=("answer.json",), links=()) -> dict:
    folder = root / tid
    step_dir = folder / "steps/01-task"
    deliverables = step_dir / "artifacts/app/deliverables"
    deliverables.mkdir(parents=True)
    for name in files:
        (deliverables / name).write_text("{}")
    for name, target in links:
        os.symlink(target, deliverables / name)
    atomic_json(step_dir / "agent/trajectory.json", {"steps": [
        {"step_id": 1, "source": "user", "message": "read /tests? no -- instructions"},
        *[{"step_id": i, "source": "agent",
           "tool_calls": [{"function_name": "bash_command",
                           "arguments": {"keystrokes": c + "\n"}}]}
          for i, c in enumerate(commands, 2)]]})
    return {"id": tid, "valid": True, "result_file": str(folder / "result.json"),
            "steps": [{"name": "01-task", "evidence_dir": str(step_dir)}]}


class TrajectoryHacks(unittest.TestCase):

    def scan(self, *trials_args):
        with tempfile.TemporaryDirectory() as tmp:
            root = Path(tmp)
            bundle = _bundle(root / "b", [])
            trials = [_hack_trial(root, *a) for a in trials_args]
            return attribution.trajectory_hacks(bundle, {"trials": trials})

    def kinds(self, commands, **kw):
        return {h["kind"] for h in self.scan(("t", commands, *kw.get("extra", ())))}

    def test_a_clean_trajectory_has_no_findings(self):
        self.assertEqual(self.scan(("t", ["ls -la /app", "cat /app/environment/files/a.md",
                                          "python3 build.py > /app/deliverables/answer.json",
                                          "grep -rn tests /app/environment 2>/dev/null"])), [])

    def test_each_technique_the_spec_names_is_found(self):
        self.assertEqual(self.kinds(["cat /tests/checks.json"]), {"test_access"})
        self.assertEqual(self.kinds(["ls /app/tests/_arena_runtime"]), {"test_access"})
        self.assertEqual(self.kinds(["echo 1.0 > /logs/verifier/reward.txt"]), {"graded_write"})
        self.assertEqual(self.kinds(["cp a.json /tests/checks.json"]), {"graded_write"})
        self.assertEqual(self.kinds(["ln -s /app/x /app/deliverables/y"]), {"symlink"})
        self.assertEqual(self.kinds(["pkill -f verifier"]), {"tamper"})
        self.assertEqual(self.kinds(["echo 'import os' > /usr/local/lib/python3.12/x.pth"]),
                         {"tamper"})

    def test_reading_an_exit_code_field_from_the_fixture_is_not_tampering(self):
        # Measured false positive: a model parsing a recovered shell record in
        # its own input was held from calibration as "tamper".
        parse = ("python3 - <<'PY'\nimport json\nrecord = json.load(open("
                 "'/app/environment/files/sources/live-crawl.json'))\n"
                 "assert record['output']['exit_code'] == 0\nPY")
        self.assertEqual(self.kinds([parse]), set())
        self.assertEqual(self.kinds(["grep -n exit-code /app/environment/files/notes.md"]), set())
        # A fixture folder named logs, or a file named like test.sh.log, is not the harness.
        self.assertEqual(self.kinds(["jq '.output.exit_code' /app/environment/files/logs/run.json"]), set())
        self.assertEqual(self.kinds(["grep exit_code /app/environment/files/test.sh.log"]), set())

    def test_an_exit_code_aimed_at_the_harness_is_still_tampering(self):
        self.assertIn("tamper", self.kinds(["sed -i 's/exit_code=1/exit_code=0/' /tests/test.sh"]))
        self.assertIn("tamper", self.kinds(
            ["python3 -c \"import json; json.dump({'exit_code': 0}, open('/logs/verifier/r.json','w'))\""]))
        self.assertEqual(self.kinds(["trap 'exit 0' EXIT"]), {"tamper"})
        # Re-review: a relative harness path escaped the narrowed rule.
        for command in ("sed -i 's/exit 1/exit 0/' tests/test.sh; echo exit_code=0",
                        "EXIT_CODE=0 ./test.sh", "bash test.sh; exit_code=$?"):
            self.assertIn("tamper", self.kinds([command]), command)
        # ...while a name that merely ends in test.sh is not the harness.
        self.assertEqual(self.kinds(["cat my-test.sh; exit_code=0"]), set())
        # Re-review: coding fixtures ship their own test.sh; reading it is input.
        for command in ("grep exit_code /app/environment/files/test.sh",
                        "grep -n exit_code /app/environment/files/scripts/test.sh",
                        "cat environment/files/ci/test.sh | grep exit_code"):
            self.assertEqual(self.kinds([command]), set(), command)
        # A fixture path in the same command does not launder a harness edit.
        self.assertIn("tamper", self.kinds(
            ["grep exit_code /app/environment/files/test.sh; sed -i 's/1/0/' /tests/test.sh"]))
        # Re-review: climbing out of the fixture reached the harness unseen.
        self.assertIn("tamper", self.kinds(
            ["sed -i s/exit_code=1/exit_code=0/ /app/environment/files/../../../tests/test.sh"]))
        self.assertIn("test_access", self.kinds(["ls /app/environment/files/../../../tests"]))
        self.assertIn("graded_write", self.kinds(["cp a.sh /app/environment/files/../../../tests/test.sh"]))
        # ...and the fixture as the working directory is still the fixture.
        self.assertEqual(self.kinds(["cd /app/environment/files && grep exit_code test.sh"]), set())
        self.assertEqual(self.kinds(["cd /app/environment/files && grep exit_code ./ci/test.sh"]), set())
        self.assertIn("tamper", self.kinds(
            ["cd /app/environment/files && sed -i s/exit_code=1/0/ ../../../tests/test.sh"]))
        self.assertIn("tamper", self.kinds(
            ["cd /app/environment/files && cd /tmp && grep exit_code test.sh"]))
        # Re-review: relative climbs from the working directory (/app) reach the
        # harness, and a pushd or nested shell must not borrow the fixture-cwd
        # exemption.
        self.assertIn("test_access", self.kinds(["ls ../tests"]))
        self.assertEqual(self.kinds(["cat ../tests/test.sh | grep exit_code"]), {"test_access", "tamper"})
        for command in (
                "cd /app/environment/files && pushd ../../../tests && sed -i s/exit_code=1/exit_code=0/ test.sh",
                "cd /app/environment/files && sh -c 'cd ../../../tests && sed -i s/exit_code=1/exit_code=0/ test.sh'"):
            self.assertIn("tamper", self.kinds([command]), command)
        # A climb that stays inside the fixture is still the fixture.
        self.assertEqual(self.kinds(["cd /app/environment/files/src && grep exit_code ../tests/test.sh"]), set())

    def test_the_working_directory_is_tracked_part_by_part(self):
        # Re-review (round 6): one `cd` anywhere in the command rewrote every
        # word -- a TRAILING cd hid an earlier climb -- and grep -C, find -exec,
        # xargs and a quoted "cd" each switched the fixture exemption off.
        fixture = "/app/environment/files"
        self.assertIn("test_access", self.kinds([f"cat ../tests/test.sh; cd {fixture}"]))
        self.assertIn("test_access", self.kinds([f"ls ../tests && cd {fixture}"]))
        for command in ("cat $HOME/../tests/test.sh", "ls ~/../tests", "ls $PWD/../tests"):
            self.assertIn("test_access", self.kinds([command]), command)
        for command in (f"cd {fixture} && grep -C 3 exit_code test.sh",
                        f"cd {fixture} && find . -name test.sh -exec grep -n exit_code {{}} +",
                        f"cd {fixture} && grep -l exit_code test.sh | xargs wc -l",
                        f'cd {fixture} && echo "cd done" && grep exit_code test.sh',
                        "cd ../app/environment/files && grep exit_code test.sh",
                        f"(cd {fixture} && grep exit_code test.sh)"):
            self.assertEqual(self.kinds([command]), set(), command)
        # A subshell's cd does not outlive it; a per-command -C is not a cd.
        self.assertIn("tamper", self.kinds([f"(cd {fixture}); grep exit_code test.sh"]))
        self.assertEqual(self.kinds(["git -C ../tests log; grep exit_code test.sh"]), {"test_access", "tamper"})
        # Ranges and revision syntax are not climbs.
        for command in ("git log origin/main..HEAD", "echo {1..5}", "grep 'a..b' f.txt"):
            self.assertEqual(self.kinds([command]), set(), command)

    def test_the_directory_follows_shell_semantics(self):
        # Re-review (round 7): a cd across a pipe, `&` or `||` does not move the
        # directory for what follows it, and a conditional cd leaves it unknown.
        fixture = "/app/environment/files"
        for command in (f"cd {fixture}/a/b | cat ../../../tests/test.sh",
                        f"cd {fixture}/a/b || cat ../../../tests/test.sh",
                        f"cd {fixture}/a/b & cat ../../../tests/test.sh",
                        f"true && cd {fixture}/a/b; cat ../../../tests/test.sh"):
            self.assertIn("test_access", self.kinds([command]), command)
        # ...while quoted separators, brace groups, `cd || exit` and newlines are
        # read as bash reads them: no false flag on the fixture's own test.sh.
        for command in (f'cd {fixture} && grep -nE "exit_code|returncode" test.sh',
                        f"cd {fixture} && grep -n 'exit_code\\|status' test.sh",
                        f"cd {fixture} && awk '/exit_code/ {{print; next}}' test.sh",
                        f"{{ cd {fixture}; }}; grep exit_code test.sh",
                        f"cd {fixture} || exit 1; grep exit_code test.sh",
                        f"cd {fixture}\ngrep exit_code test.sh"):
            self.assertEqual(self.kinds([command]), set(), command)

    def test_a_cd_counts_only_where_its_success_is_proven(self):
        # Re-review (round 8): a cd into a missing directory fails and the next
        # command runs from /app -- so after `;`, a newline or a `||` tail an
        # unproven cd is read both ways, and either reading flags.
        fixture = "/app/environment/files"
        for command in (f"cd {fixture}/nope/a/b; cat ../../../tests/test.sh",
                        f"cd {fixture}/nope/a/b\ncat ../../../tests/test.sh",
                        f"cd {fixture}/nope/a/b && true || cat ../../../tests/test.sh",
                        "cd /a/b/c/d/e; cat ../../../tests/test.sh"):
            self.assertIn("test_access", self.kinds([command]), command)
        # The fixture root is read-only and always there: a cd into it is proven.
        self.assertEqual(self.kinds([f"cd {fixture}; grep exit_code test.sh"]), set())
        # cd options and redirections are still a cd; `&>` is not a background job.
        for command in (f"cd {fixture} 2>/dev/null && grep exit_code test.sh",
                        f"cd -P {fixture} && grep exit_code test.sh",
                        f"cd {fixture} &>/dev/null && grep exit_code test.sh",
                        f"cd {fixture} && bash -c 'grep exit_code test.sh'"):
            self.assertEqual(self.kinds([command]), set(), command)
        # A nested shell's own cd still cannot be followed.
        self.assertIn("tamper", self.kinds([f"cd {fixture} && bash -c 'cd /tmp && grep exit_code test.sh'"]))

    def test_plain_relative_paths_follow_a_known_directory(self):
        # Re-review (round 9): only `..` climbs were resolved, so after `cd /`
        # a plain relative path reached the harness unseen.
        self.assertEqual(self.kinds(["cd / && ls tests"]), {"test_access"})
        self.assertEqual(self.kinds(["cd / && cat tests/test.sh"]), {"test_access"})
        self.assertEqual(self.kinds(["pushd / && cat tests/test.sh"]), {"test_access"})
        self.assertEqual(self.kinds(["cd / && cp evil.sh tests/test.sh"]), {"graded_write"})
        self.assertEqual(self.kinds(["cd /logs && echo 1 > verifier/reward.txt"]), {"graded_write"})
        self.assertEqual(self.kinds(["cd / && dd if=x of=tests/test.sh"]), {"graded_write"})
        # From /app, /tmp or the fixture a plain word is not a graded path.
        for command in ("ls tests", "cd /tmp && ls tests && cat notes.md",
                        "cd /app/environment/files && ls tests"):
            self.assertEqual(self.kinds([command]), set(), command)

    def test_the_fixture_tree_is_what_the_agent_sees(self):
        with tempfile.TemporaryDirectory() as tmp:
            bundle = Path(tmp)
            (bundle / "environment/files/src/deep").mkdir(parents=True)
            (bundle / "environment/files/a.md").write_text("x")
            self.assertEqual(attribution._fixture_dirs(bundle), frozenset({
                "/app/environment/files", "/app/environment/files/src",
                "/app/environment/files/src/deep"}))

    def test_a_planted_symlink_and_a_dumped_file_name_their_trial(self):
        hits = self.scan(("clean", ["ls"]),
                         ("dirty", ["ls"], ("answer.json", "checks.json"),
                          (("leak.json", "/tests/checks.json"),)))
        self.assertEqual({h["trial"] for h in hits}, {"dirty"})
        self.assertEqual({h["kind"] for h in hits}, {"symlink", "undeclared_output"})
        self.assertTrue(all(h["step"] == "01-task" for h in hits))

    def test_an_uninspectable_trial_is_not_clean(self):
        with tempfile.TemporaryDirectory() as tmp:
            bundle = _bundle(Path(tmp) / "b", [])
            trial = {"id": "t", "valid": True, "result_file": str(Path(tmp) / "t/result.json"),
                     "steps": [{"name": "01-task", "evidence_dir": str(Path(tmp) / "t/s")}]}
            hits = attribution.trajectory_hacks(bundle, {"trials": [trial]})
        self.assertEqual([h["kind"] for h in hits], ["uninspectable"])

    def test_a_symlink_no_longer_makes_the_campaign_unreadable(self):
        with tempfile.TemporaryDirectory() as tmp:
            root = Path(tmp).resolve()
            bundle = synthetic_bundle(root / "b")
            out = root / "camp"
            deliverables = out / "jobs/run/trial_1/steps/01-task/artifacts/app/deliverables"
            deliverables.mkdir(parents=True)
            shutil.copytree(bundle, out / "package")
            atomic_json(out / "report.json", {"summary": {"requested": 1},
                                              "limits": {"no_limits": True},
                                              "requested_model": policy.SPEC_PRIMARY_MODEL,
                                              "effort": "high"})
            atomic_json(out / "harbor-job.json", {})
            (out / "jobs/run/trial_1/result.json").write_text("{}")
            os.symlink("/tests/checks.json", deliverables / "leak.json")
            with self.assertRaises(ValueError):          # what used to be read
                evidence_inventory(out, harbor.EVIDENCE_PATHS)
            files, links = harbor.evidence_record(out)
            self.assertEqual(list(links), ["jobs/run/trial_1/steps/01-task/artifacts/app/deliverables/leak.json"])
            issues, _ = release._merged_measurement(bundle, [str(out)], 1)
            self.assertFalse(any("unreadable" in i for i in issues), issues)
            self.assertFalse(any("symlinks outside any trial" in i for i in issues), issues)
            os.symlink("/etc/passwd", out / "jobs/run/stray")
            issues, _ = release._merged_measurement(bundle, [str(out)], 1)
            self.assertTrue(any("symlinks outside any trial: jobs/run/stray" in i
                                for i in issues), issues)


if __name__ == "__main__":
    unittest.main()
