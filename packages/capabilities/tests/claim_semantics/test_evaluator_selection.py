"""The verdict is the receipt's, not the toolchain's: every evaluator set agrees.

``--evaluator`` chooses which kernels judge.  The whole point of making the
Soufflé kernels opt-in is that choosing fewer of them must change *what is
recorded about the run* -- which kernels ran, whether a differential ran -- and
nothing about the answer.  This module pins that from both sides:

* **Host, no optional tool.**  The python-only judge is run over every committed
  receipt fixture and compared, field by field, against
  ``fixtures/expected_judge_verdicts.json`` -- the verdicts, per-op
  qualifications, missing premises and certificate digests **recorded from a
  three-kernel devShell run** (``record.py`` beside the table, which is how the
  file is regenerated).  A python-only judge that quietly answered something
  else would fail here rather than in a reviewer's head.
* **devShell.**  ``--evaluator all`` judges the same fixtures with three kernels
  and must produce that same table, plus a differential that actually ran.  If
  it ever stops matching, the table is the thing that was recorded, so the
  failure names which side moved.

Nothing here skips for an absent Soufflé except the class that is about Soufflé.
"""
from __future__ import annotations

import json
import os
import shutil
import subprocess
import sys
import tempfile
import unittest
from pathlib import Path

from capcov.claims import differential
from capcov.claims.replay import judge as replay_judge

PACKAGE_ROOT = Path(__file__).resolve().parents[2]
FIXTURES = Path(__file__).resolve().parent / "fixtures"
EXPECTED_PATH = FIXTURES / "expected_judge_verdicts.json"
#: The committed receipts judged here, by the name the table keys them under.
RECEIPTS = {
    "qualified": FIXTURES / "replay_receipt_target_go_qualified",
    "unqualified": FIXTURES / "replay_receipt_target_go_unqualified",
    "repeat": FIXTURES / "replay_receipt_target_go_repeat",
    "synthetic": FIXTURES / "replay_receipt_min",
}
SOUFFLE_ONLY = "this assertion is about the souffle interpreter; it is not on PATH here"


def verdicts(document: dict) -> dict:
    """The part of a judge document that must not depend on which kernels ran.

    Deliberately *not* the whole document: ``kernels``, ``differential``,
    ``differential_report`` and ``compiled`` are exactly the fields that record
    which evaluators ran, and timings are wall clock.  Everything else -- the
    verdict, the exit code, every op's qualification, its missing premises, its
    blocking premise and the sha256 of its certificate -- is the judgement, and
    the judgement is the receipt's.
    """
    return {key: document[key] for key in
            ("verdict", "exit_code", "ops", "required_ops", "contract_findings", "learn")
            if key in document} | {
        key: document[key] for key in ("unmet_ops", "pending_ops", "message")
        if key in document}


def judge(receipt: Path, out: Path, evaluator: str | None) -> dict:
    document, _ = replay_judge.judge_receipt(receipt, out, [], evaluators=evaluator)
    return document


def expected() -> dict:
    return json.loads(EXPECTED_PATH.read_text(encoding="utf-8"))


class PythonOnlyJudgeMatchesTheRecordedVerdicts(unittest.TestCase):
    """No optional tool, no flag: the same verdicts the three-kernel run recorded."""

    @classmethod
    def setUpClass(cls) -> None:
        cls.tmp = Path(tempfile.mkdtemp(prefix="capcov-evaluator-selection-"))
        cls.table = expected()
        cls.documents = {
            name: judge(receipt, cls.tmp / name, "python")
            for name, receipt in sorted(RECEIPTS.items())}

    @classmethod
    def tearDownClass(cls) -> None:
        shutil.rmtree(cls.tmp, ignore_errors=True)

    def test_the_table_covers_every_committed_receipt(self) -> None:
        self.assertEqual(set(self.table["receipts"]), set(RECEIPTS))
        self.assertEqual(self.table["recorded_with"],
                         ["python", "souffle", "souffle-compiled"],
                         "the table is only worth comparing against if three kernels produced it")

    def test_every_receipt_yields_its_recorded_verdict(self) -> None:
        for name, document in sorted(self.documents.items()):
            with self.subTest(receipt=name):
                self.assertEqual(verdicts(document), self.table["receipts"][name])

    def test_the_two_real_fixtures_are_the_documented_pending_and_unsupported(self) -> None:
        """Spelled out, so the table cannot drift into agreeing with a wrong answer."""
        self.assertEqual(self.documents["qualified"]["verdict"], "pending-premise")
        self.assertEqual(self.documents["qualified"]["exit_code"], 5)
        self.assertEqual(self.documents["qualified"]["ops"]["delete-issue"]["qualification"],
                         "pending model_well_formed")
        self.assertEqual(self.documents["unqualified"]["verdict"], "not-supported")
        self.assertEqual(self.documents["unqualified"]["exit_code"], 1)
        self.assertEqual(self.documents["unqualified"]["ops"]["delete-issue"]["blocking_premise"],
                         {"relation": "undeclared_any", "holds": True})
        # and the synthetic receipt, the only one carrying a Stage D certificate,
        # is the positive control: a python-only judge still reaches "supported"
        self.assertEqual(self.documents["synthetic"]["verdict"], "supported")
        self.assertEqual(self.documents["synthetic"]["exit_code"], 0)

    def test_each_document_records_one_kernel_and_no_differential(self) -> None:
        for name, document in sorted(self.documents.items()):
            with self.subTest(receipt=name):
                self.assertEqual(document["kernels"], ["python"])
                self.assertEqual(document["differential"], "not-run (single evaluator)")
                self.assertIsNone(document["compiled"])

    def test_certificate_digests_are_the_ones_the_three_kernel_run_certified(self) -> None:
        """The strongest field in the table: a certificate is bytes, not a verdict."""
        signed = 0
        for name, document in sorted(self.documents.items()):
            for op, entry in sorted(document["ops"].items()):
                recorded = self.table["receipts"][name]["ops"][op]["certificate_sha256"]
                with self.subTest(receipt=name, op=op):
                    self.assertEqual(entry["certificate_sha256"], recorded)
                signed += entry["certificate_sha256"] is not None
        self.assertGreater(signed, 0, "no receipt certified an op_qualified row")


class EvaluatorSetsDoNotChangeTheAnswer(unittest.TestCase):
    """Two evaluators, three evaluators: the same table, and a differential that ran."""

    @classmethod
    def setUpClass(cls) -> None:
        cls.tmp = Path(tempfile.mkdtemp(prefix="capcov-evaluator-agreement-"))
        cls.table = expected()

    @classmethod
    def tearDownClass(cls) -> None:
        shutil.rmtree(cls.tmp, ignore_errors=True)

    @unittest.skipUnless(shutil.which("souffle"), SOUFFLE_ONLY)
    def test_all_runs_three_kernels_and_reaches_the_recorded_verdicts(self) -> None:
        for name, receipt in sorted(RECEIPTS.items()):
            document = judge(receipt, self.tmp / f"all-{name}", "all")
            with self.subTest(receipt=name):
                self.assertEqual(document["kernels"],
                                 ["python", "souffle", "souffle-compiled"])
                self.assertEqual(document["differential"], "ran")
                self.assertTrue(document["differential_report"]["matched"])
                self.assertTrue(document["differential_report"]["closure_digest_equal"])
                self.assertEqual(verdicts(document), self.table["receipts"][name])

    @unittest.skipUnless(shutil.which("souffle"), SOUFFLE_ONLY)
    def test_the_pairwise_set_runs_two_kernels_and_reaches_them_too(self) -> None:
        document = judge(RECEIPTS["qualified"], self.tmp / "pair", "python,souffle")
        self.assertEqual(document["kernels"], ["python", "souffle"])
        self.assertEqual(document["differential"], "ran")
        self.assertIsNone(document["compiled"], "no binary is compiled for the pairwise ask")
        self.assertEqual(verdicts(document), self.table["receipts"]["qualified"])


class EvaluatorResolutionTests(unittest.TestCase):
    """What ``--evaluator`` accepts, refuses, and what it never does silently."""

    def test_the_default_is_python_alone(self) -> None:
        self.assertEqual(differential.resolve_evaluators(None), ("python",))

    def test_a_comma_list_is_ordered_and_deduplicated(self) -> None:
        self.assertEqual(differential.resolve_evaluators("souffle-compiled,python,souffle"),
                         ("python", "souffle", "souffle-compiled"))
        self.assertEqual(differential.resolve_evaluators("python,python"), ("python",))

    def test_all_is_every_available_evaluator_and_python_is_always_one(self) -> None:
        resolved = differential.resolve_evaluators("all")
        self.assertIn("python", resolved)
        self.assertEqual(resolved, differential.available_evaluators())
        if shutil.which("souffle") is None:
            self.assertEqual(resolved, ("python",))
        else:
            self.assertEqual(resolved, ("python", "souffle", "souffle-compiled"))

    def test_an_unknown_name_is_refused_rather_than_ignored(self) -> None:
        with self.assertRaises(differential.UnknownEvaluator) as caught:
            differential.resolve_evaluators("python,coq")
        self.assertIn("unknown evaluator 'coq'", str(caught.exception))

    def test_requiring_an_absent_souffle_names_the_tool_and_the_way_out(self) -> None:
        with self.assertRaises(differential.EvaluatorUnavailable) as caught:
            differential.require_evaluators(("souffle",), executable="souffle-not-installed")
        message = str(caught.exception)
        self.assertIn("--evaluator souffle needs the Souffle 2.5 executable", message)
        self.assertIn("souffle-not-installed", message)
        self.assertIn("not on PATH or $SOUFFLE", message)
        self.assertIn("Install it with:", message)
        self.assertIn("or use --evaluator python", message)

    def test_requiring_python_never_raises(self) -> None:
        differential.require_evaluators(("python",), executable="souffle-not-installed")

    def test_the_souffle_executable_honours_the_environment(self) -> None:
        import os

        self.assertEqual(differential.souffle_executable("explicit"), "explicit")
        previous = os.environ.get("SOUFFLE")
        os.environ["SOUFFLE"] = "/opt/souffle/bin/souffle"
        try:
            self.assertEqual(differential.souffle_executable(), "/opt/souffle/bin/souffle")
        finally:
            if previous is None:
                del os.environ["SOUFFLE"]
            else:
                os.environ["SOUFFLE"] = previous
        self.assertEqual(differential.souffle_executable(), previous or "souffle")

    def test_a_single_evaluator_that_fails_is_not_an_agreement_with_itself(self) -> None:
        """Fail-closed with one kernel: a named operational failure is never a verdict.

        With two kernels a failure blocks through ``reports_match``.  With one
        there is nothing to compare it against, so the check has to be made
        explicitly -- otherwise a kernel that produced no closure at all would be
        recorded as ``matched`` and its (empty) relations certified.
        """
        from capcov.claims.replay import pack as replay_pack

        planted = differential.KernelReport("python", (), (), "python-evaluation-invalid",
                                            "planted failure")
        root = Path(tempfile.mkdtemp(prefix="capcov-evaluator-failed-"))
        self.addCleanup(shutil.rmtree, root, True)
        with self.assertRaises(differential.EvaluatorMismatch) as caught:
            differential.run_evaluators(replay_pack.pack_bundle(), ("python",),
                                        runners={"python": lambda bundle: planted},
                                        replay_root=root)
        self.assertIn("claim evaluator failed (python: python-evaluation-invalid)",
                      str(caught.exception))
        self.assertFalse(caught.exception.result.matched)
        self.assertEqual(caught.exception.result.differential, "not-run (single evaluator)")
        self.assertTrue(sorted(root.glob("evaluators-*.json")),
                        "the bundle nothing could answer for is persisted for replay")

    def test_a_single_evaluator_result_says_the_differential_did_not_run(self) -> None:
        """The fail-closed property in miniature: ``matched`` alone must not be readable
        as "the kernels agreed" when there was only one of them."""
        from capcov.claims.replay import pack as replay_pack

        result = differential.run_evaluators(replay_pack.pack_bundle(), ("python",))
        self.assertEqual(result.evaluators, ("python",))
        self.assertEqual(result.differential, "not-run (single evaluator)")
        self.assertTrue(result.matched)
        self.assertIsNone(result.souffle)
        self.assertIsNone(result.compiled)
        self.assertEqual([report.backend for report in result.reports], ["python"])


class AssumptionsCliEvaluatorTests(unittest.TestCase):
    """The experiment CLI takes the same flag, with the same default and refusal.

    ``capcov experiment claims assumptions`` judges a receipt to build its A2
    registry, so it had the same hard dependency on the interpreter.  PATH is
    emptied for every run here so the answers do not depend on whether this
    machine happens to have Souffle.
    """

    def _run(self, *extra: str):
        return subprocess.run(
            [sys.executable, "-m", "capcov", "experiment", "claims", "assumptions",
             "registry", "--receipt", str(RECEIPTS["qualified"]), *extra],
            text=True, capture_output=True, cwd=str(PACKAGE_ROOT),
            env={**os.environ, "PATH": "", "PYTHONPATH": str(PACKAGE_ROOT / "src")})

    def test_the_default_builds_the_registry_with_no_tool_on_path(self) -> None:
        proc = self._run()
        self.assertEqual(proc.returncode, 0, proc.stderr[-2000:])
        document = json.loads(proc.stdout)
        self.assertTrue(document["registry"]["assumptions"])

    def test_asking_for_souffle_without_it_is_a_named_refusal(self) -> None:
        proc = self._run("--evaluator", "souffle")
        self.assertEqual(proc.returncode, 2, proc.stderr[-2000:])
        refusal = json.loads(proc.stdout)["refusal"]
        self.assertIn("--evaluator souffle needs the Souffle 2.5 executable", refusal)
        self.assertIn("or use --evaluator python", refusal)

    def test_an_unknown_evaluator_is_refused_before_the_receipt_is_read(self) -> None:
        proc = self._run("--evaluator", "datalog")
        self.assertEqual(proc.returncode, 2, proc.stderr[-2000:])
        self.assertIn("unknown evaluator 'datalog'", json.loads(proc.stdout)["refusal"])


if __name__ == "__main__":
    unittest.main()
