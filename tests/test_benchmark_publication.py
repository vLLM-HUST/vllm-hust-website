import hashlib
import json
from pathlib import Path
from html.parser import HTMLParser

ROOT = Path(__file__).resolve().parents[1]


def test_v102_actual_failure_and_model_diagnostic_remain_visible():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    results = data["acceptance_completion"]
    assert results["continuous"]["paired_continuous_stability_pass"] is False
    assert results["continuous"]["b1_attempts"][1]["failed_requests"] == 8
    assert results["continuous"]["b1_attempts"][1]["long16k_executed"] is False
    assert [arm["correct"] for arm in results["out256_quality"]["arms"]] == [21, 19]
    assert results["reference"]["current_v15_attainment"] is None
    assert (
        results["reference"]["graph_recomputation"][0]["reference_tflops_per_chip"] > 19
    )
    section = next(s for s in data["sections"] if s["id"] == "acceptance-completion")
    assert section["id"] == "acceptance-completion"
    assert len(section["title"].split(" / ")) == 2
    assert section["tables_en"] and section["source_heading"]
    loader = (ROOT / "assets/b0-b1.js").read_text()
    assert "B0_completed_B1_measured_host_allocation_failure" in loader
    assert "新参考需独立推导与整链实现见证" not in loader


def test_wave2_failures_and_break_filter_control_remain_distinct():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    flipt, vuls, teleport = data["swe_incremental_tasks"]["entries"][21:24]
    assert flipt["raw_test_coverage"]["target_tests_executed"] is False
    assert vuls["request_audit"]["attempts"] == 20 and vuls["model_calls"] == 19
    assert vuls["patch_bytes"] == 0 and vuls["apply_exit_code"] == 128
    assert vuls["patch_application_attested"] is False
    assert vuls["application_state_capture_incomplete"] is True
    assert teleport["raw_test_observation"]["target_tests_executed"] is True
    assert teleport["official_test_coverage"]["fail_to_pass"]["missing"] == 0
    controls = data["terminal_break_filter_controls"]
    assert controls["original_r1"]["reward"] is None
    assert controls["r2"]["controls"]["oracle"]["reward"] == 0
    assert controls["boundary"]["model_task_score"] is None
    assert controls["boundary"]["new_model_task_attempts"] == 0
    assert (
        repr("reports/terminal-break-filter-controls-20261027/summary.json")
        in (ROOT / "assets/midterm-report.js").read_text()
    )


def test_flipt_raw_failures_and_parser_coverage_are_disclosed():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    section = next(
        s for s in data["sections"] if s["id"] == "swe-single-agent-observation"
    )
    assert "14通过、2失败" in section["scope"]
    assert "2个包初始化失败" in section["scope"]
    assert "实际执行并失败" in section["scope"]
    assert "14 passed, 2 failed" in section["scope_en"]
    assert "2 package setup failures" in section["scope_en"]
    assert "target executed and failed" in section["scope_en"]
    assert section["evidence"][0]["path"] == (
        "reports/swe-native018-wave2-openlibrary-navidrome-20261027/catalog.json"
    )


def test_v099_preserves_unscored_and_partial_boundaries():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    recovery = data["protonmail_test_source_recovery"]
    assert recovery["test_source_restored"] is True
    assert recovery["accepted_functional_score"] is None
    assert recovery["tests_executed"] == recovery["new_model_calls"] == 0
    assert recovery["new_Agent_attempts"] == 0
    controls = data["terminal_cython_controls"]
    assert controls["control_qualification_passed"] is False
    assert controls["new_model_task_attempts"] == controls["model_calls"] == 0
    section = next(
        s for s in data["sections"] if s["id"] == "swe-single-agent-observation"
    )
    assert "76次HTTP" in section["scope"]
    assert "76 HTTP" in section["scope_en"]
    assert "4/26" in section["scope"] and "4/26" in section["scope_en"]
    assert section["tables"][0]["rows"][16][2] == "75成功 + 1拒绝"
    assert "未提交部分补丁" in section["tables"][0]["rows"][16][-1]
    loader = (ROOT / "assets/midterm-report.js").read_text()
    for path in (
        "reports/swe-native018-navidrome-20261027/catalog.json",
        "reports/swe-protonmail-test-source-recovery-20261027/summary.json",
        "reports/terminal-build-cython-controls-20261027/summary.json",
    ):
        assert repr(path) in loader


def test_current_and_retained_swe_evidence_paths_remain_allowed():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    loader = (ROOT / "assets/midterm-report.js").read_text()
    for section in data["sections"]:
        for source in section["evidence"]:
            if source["path"].startswith("reports/swe-native018-"):
                assert repr(source["path"]) in loader


def test_c16_latency_is_existing_request_weighted_evidence():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    value = data["c16_equal_request_latency"]
    assert value["new_inference_requests"] == 0
    assert [arm["window"]["requests"] for arm in value["arms"]] == [392, 1280]
    assert [arm["including_drain"]["requests"] for arm in value["arms"]] == [408, 1296]
    assert value["method"]["weighting"] == "equal weight per successful request"
    section = next(s for s in data["sections"] if s["id"] == "c16-request-latency")
    assert section["tables"][0]["rows"] == section["tables_en"][0]["rows"]
    assert "质量/SLO" in section["scope"]
    assert "not full acceptance" in section["scope_en"]
    assert (
        section["evidence"][0]["path"]
        in (ROOT / "assets/midterm-report.js").read_text()
    )


def test_hle_completion_and_swe_single_attempt_are_not_full_acceptance():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    assert data["hle_designated_baseline"]["gold"]["successes"] == 157
    assert data["hle_designated_baseline"]["revision"]["successes"] == 316
    swe = data["swe_single_agent"]
    assert swe["executed_tasks"] == 1 and swe["resolved"] == 0
    assert swe["qualification"]["model_calls"] == 5
    assert swe["agent"]["status"] == "LimitsExceeded"
    assert swe["unresolved_grading"] == 0 and not swe["full_dataset_acceptance"]
    sections = {s["id"]: s for s in data["sections"]}
    for key in ("tables", "tables_en"):
        rows = {row[0]: row for row in sections["v15-remaining"][key][0]["rows"]}
        assert "23/31" in rows["HLE-Verified"][1]
        assert "3/26" in rows["SWE-bench-Pro"][1]
    catalog = data["swe_incremental_tasks"]
    assert catalog["attempted_unique_tasks"] == 26
    assert catalog["confirmed_patch_application_failure_tasks"] == 3
    assert catalog["unattempted_tasks"] == 705
    assert catalog["application_evidence_limited_tasks"] == 1
    assert catalog["recorded_official_resolved"] == 3
    for key in ("tables", "tables_en"):
        assert len(sections["swe-single-agent-observation"][key][0]["rows"]) == 26
    assert catalog["confirmed_target_compilation_failure_tasks"] == 4
    assert catalog["entries"][-1]["official_resolved"] == 0
    terminal = data["terminal_arm64_controls"]
    assert terminal["model_calls"] == terminal["official_89_task_model_coverage"] == 0
    assert [(c["passed"], c["reward"]) for c in terminal["controls"]] == [
        (0, 0),
        (6, 1),
    ]
    for key in ("tables", "tables_en"):
        assert len(sections["terminal-arm64-controls"][key][0]["rows"]) == 2
        assert len(sections["terminal-model-recovery"][key][0]["rows"]) == 2
    cancel = data["terminal_cancel_controls"]
    assert cancel["model_calls"] == cancel["model_task_attempts"] == 0
    assert [(c["passed"], c["reward"]) for c in cancel["controls"]] == [(0, 0), (6, 1)]
    for key in ("tables", "tables_en"):
        assert len(sections["terminal-cancel-async-controls"][key][0]["rows"]) == 2
    recovered = data["terminal_model_recovery"]
    assert recovered["model_task_attempts"] == recovered["scored_model_tasks"] == 1
    assert recovered["recovery"]["passed"] == 6 and recovered["unattempted_tasks"] == 88
    assert recovered["original_verifier"]["reward"] is None
    assert recovered["recovery"]["additional_model_calls"] == 0
    assert not recovered["script_provenance"]["original_filesystem_sha_captured"]
    loader = (ROOT / "assets/midterm-report.js").read_text()
    for name in ("hle-designated-baseline", "swe-single-agent-observation"):
        assert sections[name]["evidence"][0]["path"] in loader


def test_all_data_files_match_the_benchmark_publication_manifest():
    assert "b0-b1.js?v=c16-restored-20261031" in (ROOT / "b0-b1.html").read_text()
    manifest_path = ROOT / "data/benchmark-source-manifest.json"
    manifest = json.loads(manifest_path.read_text())
    assert manifest["repository"] == "vLLM-HUST/vllm-hust-benchmark"
    entries = manifest["files"]
    expected = {entry["website_path"] for entry in entries}
    actual = {
        path.relative_to(ROOT).as_posix()
        for path in (ROOT / "data").rglob("*")
        if path.is_file() and path != manifest_path
    }
    assert actual == expected
    assert len(entries) == len(expected)
    for entry in entries:
        assert entry["benchmark_path"].startswith("website-publication/data/")
        raw = (ROOT / entry["website_path"]).read_bytes()
        assert hashlib.sha256(raw).hexdigest() == entry["sha256"]
        assert len(raw) == entry["bytes"]


def test_v099_same_answer_recovery_and_diagnostic_bounds():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    s = data["protonmail_dependency_recovery"]
    assert s["derived_dependency_recovery_result"]["official"] is True
    assert s["derived_dependency_recovery_result"]["passed"] == 3
    assert s["Agent_attempts_added"] == s["model_requests_added"] == 0
    assert s["aggregate_distinction"]["attempted_tasks"] == 17
    assert s["aggregate_distinction"]["original_official_positives"] == 2
    assert s["aggregate_distinction"]["positives_after_disclosed_recovery"] == 3
    assert s["controller_exit"] == 1 and s["grading_process_exit"] == 0
    trace = data["terminal_cython_single_trace"]
    assert trace["original_trace_recovered"] is False
    assert trace["new_model_calls"] == trace["new_control_scores"] == 0
    assert trace["diagnostic"]["missing_attribute"] == "pos"
    assert trace["original_control"]["oracle_reward"] == 0
    loader = (ROOT / "assets/midterm-report.js").read_text()
    for path in (
        "reports/swe-protonmail-dependency-recovery-20261027/summary.json",
        "reports/terminal-cython-single-trace-20261027/summary.json",
    ):
        assert repr(path) in loader


def test_tutanota_partial_compilation_failure_and_current_counts():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    value = data["swe_incremental_tasks"]["entries"][17]
    assert value["model_calls"] == 100
    assert value["official_resolved"] == 0
    assert value["agent_submitted"] is False
    assert value["status"] == "LimitsExceeded"
    aggregate = data["swe_same_answer_recovery_aggregate"]
    assert aggregate["attempted_tasks"] == aggregate["recovery_denominator"] == 26
    assert aggregate["original_official_positives"] == 3
    assert aggregate["positives_after_disclosed_recovery"] == 4
    assert aggregate["unattempted_tasks"] == 705
    assert aggregate["prior_recovery_snapshot"]["attempted_tasks"] == 17
    section = next(
        s for s in data["sections"] if s["id"] == "swe-single-agent-observation"
    )
    assert "目标测试尚未执行" in section["scope"]
    assert "before the target test ran" in section["scope_en"]


def test_cython_reconstruction_does_not_replace_original_null():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    original = data["terminal_cython_original_model"]
    assert original["reward"] is original["verifier"] is original["CTRF"] is None
    assert original["HTTP_success"] == 29 and original["HTTP_rejected"] == 1
    assert original["HTTP_requests"] == original["Harbor_episode_counter"] == 30
    recovery = data["terminal_cython_reconstructed_recovery"]
    assert recovery["reward"] == 0 and recovery["original_reward"] is None
    assert recovery["test_counts"] == {"passed": 10, "failed": 1, "missing": 0}
    assert recovery["terminal_model_attempts"] == 3
    assert recovery["terminal_unattempted"] == 86
    assert (
        recovery["new_Agent_model_controls"]
        == recovery["additional_model_attempts"]
        == 0
    )
    assert not recovery["original_native_or_install_snapshot"]
    assert recovery["local_Git_baseline_is_derived"]
    assert recovery["failure"]["fixed_numpy_version"] == "2.3.0"


class Elements(HTMLParser):
    def __init__(self):
        super().__init__()
        self.ids = []
        self.links = []
        self.scripts = []

    def handle_starttag(self, tag, attrs):
        attrs = dict(attrs)
        if "id" in attrs:
            self.ids.append(attrs["id"])
        if tag == "a":
            self.links.append(attrs.get("href", ""))
        if tag == "script":
            self.scripts.append(attrs.get("src", ""))


def test_midterm_loader_cache_key_matches_publication_version():
    loader = (ROOT / "assets/midterm-report.js").read_text()
    assert "./data/midterm-v103.json" in loader
    hero = (ROOT / "assets/current-measurements.js").read_text()
    assert "./data/midterm-v103.json" in hero
    assert "report.version !== 'V1.03'" in hero
    assert "midterm-v076.json" not in hero
    for page in ("dataset-validation.html", "leaderboard-runs.html"):
        assert (
            "current-measurements.js?v=clarity-v103-20261030"
            in (ROOT / page).read_text()
        )
    payload = json.loads((ROOT / "data/midterm-v103.json").read_text())
    assert payload["version"] == "V1.03"
    pair = payload["frontierscience_designated_pair"]
    assert pair["quality_passed"] is None
    assert [pair["B0"][t]["successes"] for t in ("olympiad", "research")] == [66, 3]
    assert [pair["B1"][t]["successes"] for t in ("olympiad", "research")] == [62, 2]
    assert "frontierscience-native018-paired-20261025" in loader
    assert (
        payload["corrected_quality"]["reference"]["eta_percent"]
        == payload["wholechain_reference"]["B1"]["eta_percent"]
    )
    assert (
        payload["historical_current_summary_v102"]["quality"]["b1"]["candidate_correct"]
        == 156
    )
    assert (
        payload["historical_current_summary_v102"]["quality"]["b1"][
            "original_controller_status"
        ]
        == "failed"
    )
    joint = payload["full_answer_joint"]
    assert (
        payload["current_summary"]["quality"]["b0"]["correct"]
        == joint["arms"][0]["correct"]
    )
    assert (
        payload["current_summary"]["quality"]["b1"]["candidate_correct"]
        == joint["arms"][1]["correct"]
    )
    assert joint["same_run_quality_and_performance"] is True
    assert joint["protocol"]["max_completion_tokens"] == 8192
    assert payload["sections"][0]["id"] == "full-answer-joint"
    assert "C / C_reference" in payload["m01_method"]["efficiency_formula"]
    assert (
        payload["m01_method"]["current"]["reference_effective_tflops_per_chip"]
        == payload["wholechain_reference"]["reference_C_TFLOPS_per_chip"]
    )
    inventory = next(
        section
        for section in payload["sections"]
        if section["id"] == "dataset-quality-inventory"
    )
    assert len(inventory["tables"]) == 6
    assert sum(len(table["rows"]) for table in inventory["tables"]) == 24
    assert [row[1] for row in inventory["tables"][-1]["rows"]] == [
        "151 / 200",
        "152 / 200",
        "149 / 200",
        "146 / 200",
    ]
    assert (
        "reports/mmlu-quality018-20261022/quality018-completed-audit-r1.json" in loader
    )
    for filename in ("dataset-validation.html", "leaderboard-runs.html"):
        parser = Elements()
        parser.feed((ROOT / filename).read_text())
        assert [src for src in parser.scripts if "midterm-report.js" in src] == [
            "./assets/midterm-report.js?v=midterm-v103-joint-20261030"
        ]


def test_three_destinations_preserve_sections_without_duplicate_ids():
    for page, ids in {
        "leaderboard-runs.html": {
            "frontier-panel",
            "fixed-targets",
            "official-target-body",
            "leaderboard-tbody",
        },
        "dataset-validation.html": {
            "matrix-content",
            "validation-content",
            "coverage-content",
        },
        "serving-plan.html": {"plan-options", "computed"},
    }.items():
        parser = Elements()
        parser.feed((ROOT / page).read_text())
        assert len(parser.ids) == len(set(parser.ids))
        assert ids <= set(parser.ids)
    for obsolete in (
        "leaderboard.html",
        "dataset-matrix-v1.html",
        "capability-coverage.html",
    ):
        assert not (ROOT / obsolete).exists()
        for page in ROOT.glob("*.html"):
            parser = Elements()
            parser.feed(page.read_text())
            assert not any(
                link.split("#")[0].split("?")[0].endswith("/" + obsolete)
                for link in parser.links
            )


def test_v15_current_method_is_bilingual_and_not_historical_acceptance():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    method = data["m01_method"]
    assert method["method_version"] == "reference-model-reassessment-20261029"
    assert method == data["milestone_contract"]["method"]
    assert method["identity"]["formal_indicator_amendment"] is False
    assert method["identity"]["original_v15"]["threshold_percent"] == 50
    assert method["current"]["passed"] is None
    assert data["wholechain_reference"]["reference_C_TFLOPS_per_chip"] is None
    assert data["wholechain_reference"]["reference_qualified"] is False
    supplement = data["reference_supplement"]
    assert supplement["totals"]["numerical_checks"] == 1402
    assert supplement["model_validation"]["passed"] == 6
    assert supplement["model_validation"]["failed"] == 26
    assert supplement["efficiency_percent"] is supplement["attainment"] is None
    assert (
        method["current"]["efficiency_percent"]
        == data["wholechain_reference"]["B1"]["eta_percent"]
    )
    assert method["current"]["effective_tflops_per_chip"] == 7.1042207644080255
    assert method["current"]["effective_flops"] == 1812905151088034
    assert method["current"]["matched_uninstrumented_seconds"] is None
    assert method["current_measurement"]["strict_uninstrumented"] is False
    assert method["measured_synchronized_b1"]["completed"] == 200
    assert method["measured_synchronized_b1"]["failed"] == 0
    assert (
        method["measured_synchronized_b1"]["synchronized_seconds"] == 120.65347687713802
    )
    audit = data["milestone_contract"]
    assert audit["cost_method"]["lifecycle_is_current_gate"] is False
    assert audit["stability_method"]["six_probe_pass_is_task_stability_pass"] is False
    sections = {s["id"]: s for s in data["sections"]}
    assert "正式参考验收修订中" in sections["m01-verdict"]["scope"]
    assert "under revision" in sections["m01-verdict"]["scope_en"]
    pair = data["paired_own_compute"]
    assert pair["rows"]["B0"]["F"] == 1829161955258989
    assert pair["eta_percent"] == data["wholechain_reference"]["B1"]["eta_percent"]
    assert pair["attainment"] is None
    assert "independently calibrated" in sections["m01-verdict"]["scope_en"]
    assert (
        method["reference_binding"]["additional_executable_witness_required"] is False
    )
    assert (
        method["reference_binding"][
            "separate_by_arm_when_work_precision_or_path_differs"
        ]
        is True
    )
    assert "不构成固定0.18/0.18 B0的M06货币成本通过" in sections["resources"]["scope"]
    assert "not M06 monetary-cost acceptance" in sections["resources"]["scope_en"]
    assert sections["milestone-v15"]["tables_en"]
    assert any(
        e["path"].endswith("/current-method.json")
        for e in sections["milestone-v15"]["evidence"]
    )
    assert sections["milestone-v15"]["tables"][0]["headers"][1] == "依据及本轮方法"
    review = sections["v15-remaining"]
    assert len(review["tables"][0]["rows"]) == 5
    assert len(review["tables_en"][0]["rows"]) == 5
    assert "22.601951%" in review["scope"]
    assert "does not improve" in review["scope_en"]
    assert "E2E is not TTFT/TPOT" in review["scope_en"]
    assert pair["rows"]["B1"]["F"] == 1812905151088034
    assert "7.1042" in review["scope_en"]


def test_partial_artifact_does_not_overwrite_unscored_trial():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    value = data["terminal_cancel_partial_recovery"]
    assert value["original_attempt"]["reward"] is None
    assert not value["original_attempt"]["task_complete"]
    assert value["original_attempt"]["HTTP200"] == 17
    assert value["original_attempt"]["HTTP400"] == 1
    assert value["recovery"]["reward"] == 0
    assert value["recovery"]["passed"] == 1 and value["recovery"]["tests"] == 6
    assert value["recovery"]["additional_model_calls"] == 0
    assert value["artifact_provenance"]["original_filesystem_sha256"] is None
    assert value["coverage"]["attempted_unique_tasks"] == 2
    assert value["coverage"]["unattempted_tasks"] == 87
    assert value["coverage"]["completed_Agent_score_for_this_task"] is None
    loader = (ROOT / "assets/midterm-report.js").read_text()
    path = "reports/terminal-cancel-async-partial-recovery-20261027/summary.json"
    assert repr(path) in loader
    browser_check = (ROOT / "scripts/verify_midterm_browser.py").read_text()
    assert path in browser_check
    assert (
        "reports/terminal-openssl-model-recovery-20261026/summary.json"
        not in browser_check
    )
    remaining = next(s for s in data["sections"] if s["id"] == "v15-remaining")
    for key in ("tables", "tables_en"):
        row = next(
            r for t in remaining[key] for r in t["rows"] if r[0] == "TerminalBench 2.1"
        )
        assert "85" in row[1] and "null" in row[1] and "4/89" in row[1]


def test_circuit_null_and_byte_diagnostic_are_not_new_scores():
    data = json.loads((ROOT / "data/midterm-v103.json").read_text())
    original = data["terminal_circuit_original_model"]
    assert (
        original["HTTP_requests"],
        original["HTTP_success"],
        original["HTTP_rejected"],
    ) == (11, 10, 1)
    assert (
        original["trajectory_agent_steps"],
        original["Harbor_n_episodes"],
        original["completed_API_latency_entries"],
    ) == (9, 10, 9)
    assert original["verifier"] is original["reward"] is original["CTRF"] is None
    assert original["answer_boundary"]["answer_write_command_found"] is False
    assert original["answer_boundary"]["original_final_answer_file_SHA_unknown"]
    assert data["terminal_circuit_request_accounting"]["usage_delta"] == {
        "prompt_tokens": 5449,
        "completion_tokens": 4096,
    }
    controls = data["terminal_circuit_controls"]
    assert controls["results"]["nop"]["passed"] == 2
    assert controls["results"]["oracle"]["passed"] == 3
    diagnostic = data["terminal_break_filter_byte_diagnostic"]
    assert (
        diagnostic["filter"]["original_output_bytes"],
        diagnostic["filter"]["filtered_bytes"],
    ) == (41, 20)
    assert diagnostic["filter"]["browser_session_started"] is False
    assert diagnostic["boundaries"]["original_positive_control_reward"] == 0
    loader = (ROOT / "assets/midterm-report.js").read_text()
    for path in (
        "reports/terminal-circuit-context-20261027/summary.json",
        "reports/terminal-circuit-controls-20261027/summary.json",
        "reports/terminal-break-filter-byte-diagnostic-20261027/summary.json",
    ):
        assert repr(path) in loader
