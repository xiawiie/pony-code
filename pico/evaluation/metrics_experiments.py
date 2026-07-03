import json
import tempfile
from contextlib import contextmanager
from pathlib import Path

from ..config import load_project_env, provider_env
from ..features import memory as memorylib
from ..providers.clients import AnthropicCompatibleModelClient, FakeModelClient, OpenAICompatibleModelClient
from ..runtime import Pico, SessionStore
from ..workspace import WorkspaceContext
from .evaluator import run_fixed_benchmark
from .metrics_common import (
    DEFAULT_CONTEXT_ABLATION_V2_PATH,
    DEFAULT_MEMORY_ABLATION_V2_PATH,
    DEFAULT_RECOVERY_ABLATION_V2_PATH,
    METRICS_SCHEMA_VERSION,
    _safe_mean,
    _safe_ratio,
    _utc_timestamp,
)


@contextmanager
def _temporary_feature_flags(agent, updates):
    previous = dict(getattr(agent, "feature_flags", {}))
    merged = dict(previous)
    merged.update(updates)
    agent.feature_flags = merged
    try:
        yield
    finally:
        agent.feature_flags = previous


def measure_feature_ablation_metrics(agent, user_message):
    variants = {
        "full": {},
        "no_context_reduction": {"context_reduction": False},
        "no_memory": {"memory": False, "relevant_memory": False},
    }
    results = {}
    for name, updates in variants.items():
        with _temporary_feature_flags(agent, updates):
            prompt, metadata = agent._build_prompt_and_metadata(user_message)
        sections = metadata.get("sections") or {}
        memory_section = sections.get("memory") or {}
        history_section = sections.get("history") or {}
        relevant_memory = metadata.get("relevant_memory") or {}
        results[name] = {
            "prompt_chars": int(metadata.get("prompt_chars", 0)),
            "memory_chars": int(memory_section.get("rendered_chars", 0)),
            "history_chars": int(history_section.get("rendered_chars", 0)),
            "relevant_selected_count": int(relevant_memory.get("selected_count", 0)),
            "budget_reduction_count": len(metadata.get("budget_reductions", [])),
            "current_request_preserved": prompt.endswith(f"Current user request:\n{user_message}"),
        }
    return results


def build_stress_agent_metrics():
    with tempfile.TemporaryDirectory(prefix="pico-metrics-") as temp_dir:
        workspace_root = Path(temp_dir)
        (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
        workspace = WorkspaceContext.build(workspace_root)
        store = SessionStore(workspace_root / ".pico" / "sessions")
        agent = Pico(
            model_client=FakeModelClient([]),
            workspace=workspace,
            session_store=store,
            approval_policy="auto",
        )
        for index in range(12):
            agent.record(
                {
                    "role": "user" if index % 2 == 0 else "assistant",
                    "content": f"stress-history-{index}-" + ("B" * 220),
                    "created_at": f"2026-04-08T11:{index:02d}:00+00:00",
                }
            )
        return measure_feature_ablation_metrics(agent, "recall")


class _MemoryExperimentModelClient(FakeModelClient):
    def __init__(self, expected_fact, filename):
        super().__init__([])
        self.expected_fact = str(expected_fact).strip().lower()
        self.filename = str(filename).strip()
        self.phase = "bootstrap_tool"
        self.followup_reads = 0

    def complete(self, prompt, max_new_tokens, **kwargs):
        del max_new_tokens, kwargs
        self.prompts.append(prompt)
        self.last_completion_metadata = {}
        if self.phase == "bootstrap_tool":
            self.phase = "bootstrap_final"
            return f'<tool>{{"name":"read_file","args":{{"path":"{self.filename}","start":1,"end":20}}}}</tool>'
        if self.phase == "bootstrap_final":
            self.phase = "question"
            return "<final>Done.</final>"
        if self.phase == "question":
            prompt_lower = prompt.lower()
            if self.expected_fact in prompt_lower:
                return f"<final>{self.expected_fact.capitalize()}.</final>"
            self.phase = "question_after_read"
            self.followup_reads += 1
            return f'<tool>{{"name":"read_file","args":{{"path":"{self.filename}","start":1,"end":20}}}}</tool>'
        if self.phase == "question_after_read":
            self.phase = "done"
            return f"<final>{self.expected_fact.capitalize()}.</final>"
        return f"<final>{self.expected_fact.capitalize()}.</final>"


def _build_memory_experiment_agent(workspace_root, expected_fact, filename):
    workspace = WorkspaceContext.build(workspace_root)
    store = SessionStore(workspace_root / ".pico" / "sessions")
    return Pico(
        model_client=_MemoryExperimentModelClient(expected_fact, filename),
        workspace=workspace,
        session_store=store,
        approval_policy="auto",
    )


def _set_irrelevant_memory(agent):
    summaries = agent.session.setdefault("memory", {}).setdefault("file_summaries", {})
    summaries.clear()
    memorylib.set_file_summary_dict(summaries, "other.txt", "team mascot is blue", workspace_root=agent.root)


def _run_memory_variant(mode):
    with tempfile.TemporaryDirectory(prefix="pico-memory-experiment-") as temp_dir:
        workspace_root = Path(temp_dir)
        (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
        (workspace_root / "facts.txt").write_text("deploy key is red\n", encoding="utf-8")
        agent = _build_memory_experiment_agent(workspace_root, "deploy key is red", "facts.txt")
        assert agent.ask("Read facts.txt and remember the key fact.") == "Done."

        if mode == "memory_off":
            agent.feature_flags["memory"] = False
            agent.feature_flags["relevant_memory"] = False
        elif mode == "memory_irrelevant":
            _set_irrelevant_memory(agent)

        result = agent.ask("What color is the deploy key?")
        task_state = agent.current_task_state
        model_client = agent.model_client
        return {
            "correct": result.strip().lower() == "deploy key is red.",
            "tool_steps": int(task_state.tool_steps),
            "attempts": int(task_state.attempts),
            "repeated_reads": int(getattr(model_client, "followup_reads", 0)),
        }


def run_memory_dependency_experiment(repetitions=3):
    variants = {
        "memory_on": [],
        "memory_off": [],
        "memory_irrelevant": [],
    }
    for _ in range(int(repetitions)):
        for variant in variants:
            variants[variant].append(_run_memory_variant(variant))

    results = {}
    for variant, rows in variants.items():
        results[variant] = {
            "repeated_reads": sum(row["repeated_reads"] for row in rows),
            "avg_tool_steps": _safe_mean(row["tool_steps"] for row in rows),
            "avg_attempts": _safe_mean(row["attempts"] for row in rows),
            "correct_rate": _safe_ratio(sum(1 for row in rows if row["correct"]), len(rows)),
        }
    return results


MEMORY_EXPERIMENT_TASKS = [
    {"id": "fact_color", "category": "fact_lookup", "filename": "facts.txt", "fact": "deploy key is red"},
    {"id": "fact_api", "category": "fact_lookup", "filename": "settings.txt", "fact": "api base path is /v1/internal"},
    {"id": "fact_budget", "category": "fact_lookup", "filename": "limits.txt", "fact": "default step budget is 6"},
    {"id": "fact_timeout", "category": "fact_lookup", "filename": "runtime.txt", "fact": "timeout ceiling is 120 seconds"},
    {"id": "edit_intro", "category": "edit_dependency", "filename": "README.md", "fact": "first bullet is the locked intro line"},
    {"id": "edit_token", "category": "edit_dependency", "filename": "sample.txt", "fact": "second token is placeholder"},
    {"id": "edit_field", "category": "edit_dependency", "filename": "config.txt", "fact": "fixed field name is benchmark_schema"},
    {"id": "edit_line", "category": "edit_dependency", "filename": "notes.txt", "fact": "locked marker is on line three"},
    {"id": "history_file", "category": "history_reference", "filename": "history.txt", "fact": "deploy fact came from facts.txt"},
    {"id": "history_line", "category": "history_reference", "filename": "history.txt", "fact": "benchmark note came from line two"},
    {"id": "history_token", "category": "history_reference", "filename": "history.txt", "fact": "placeholder token was beta"},
    {"id": "history_tool", "category": "history_reference", "filename": "history.txt", "fact": "inspection tool was read_file"},
]


def _write_memory_task_files(workspace_root, task):
    filename = task["filename"]
    payload = task["fact"]
    (workspace_root / filename).write_text(payload + "\n", encoding="utf-8")


def _bootstrap_prompt(task):
    return f"Read {task['filename']} and remember the key fact."


def _followup_prompt(task):
    if task["category"] == "fact_lookup":
        return f"What does {task['filename']} say?"
    if task["category"] == "edit_dependency":
        return f"Use the remembered constraint from {task['filename']} to continue without rereading."
    return f"What was the conclusion we already established from {task['filename']}?"


def _set_irrelevant_memory_for_task(agent):
    summaries = agent.session.setdefault("memory", {}).setdefault("file_summaries", {})
    summaries.clear()
    memorylib.set_file_summary_dict(summaries, "other.txt", "the team mascot is blue", workspace_root=agent.root)


def _run_memory_task_variant(task, variant):
    with tempfile.TemporaryDirectory(prefix="pico-memory-large-") as temp_dir:
        workspace_root = Path(temp_dir)
        (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
        _write_memory_task_files(workspace_root, task)
        agent = _build_memory_experiment_agent(workspace_root, task["fact"], task["filename"])
        assert agent.ask(_bootstrap_prompt(task)) == "Done."
        if variant == "memory_off":
            agent.feature_flags["memory"] = False
            agent.feature_flags["relevant_memory"] = False
        elif variant == "memory_irrelevant":
            _set_irrelevant_memory_for_task(agent)
        result = agent.ask(_followup_prompt(task))
        task_state = agent.current_task_state
        return {
            "correct": result.strip().lower() == f"{task['fact']}.",
            "tool_steps": int(task_state.tool_steps),
            "attempts": int(task_state.attempts),
            "repeated_reads": int(getattr(agent.model_client, "followup_reads", 0)),
        }


def run_large_scale_memory_experiment(repetitions=5):
    repetitions = int(repetitions)
    variants = {
        "memory_on": [],
        "memory_off": [],
        "memory_irrelevant": [],
    }
    for task in MEMORY_EXPERIMENT_TASKS:
        for _ in range(repetitions):
            for variant in variants:
                row = _run_memory_task_variant(task, variant)
                row["task_id"] = task["id"]
                row["category"] = task["category"]
                variants[variant].append(row)
    category_counts = {}
    for task in MEMORY_EXPERIMENT_TASKS:
        category_counts[task["category"]] = category_counts.get(task["category"], 0) + 1
    return {
        "task_count": len(MEMORY_EXPERIMENT_TASKS),
        "runs_per_variant": len(MEMORY_EXPERIMENT_TASKS) * repetitions,
        "category_counts": category_counts,
        "variants": {
            variant: {
                "repeated_reads": sum(row["repeated_reads"] for row in rows),
                "avg_tool_steps": _safe_mean(row["tool_steps"] for row in rows),
                "avg_attempts": _safe_mean(row["attempts"] for row in rows),
                "correct_rate": _safe_ratio(sum(1 for row in rows if row["correct"]), len(rows)),
                "memory_hit_rate": _safe_ratio(sum(1 for row in rows if row["repeated_reads"] == 0), len(rows)),
            }
            for variant, rows in variants.items()
        },
        "rows": variants,
    }


def run_context_stress_matrix(repetitions=5):
    repetitions = int(repetitions)
    history_levels = [("short", 4), ("medium", 12), ("long", 24)]
    note_levels = [("low", 2), ("high", 10)]
    request_levels = [("short", "recall"), ("long", "recall the relevant benchmark fact without dropping the latest request details")]
    configs = []

    for history_label, history_count in history_levels:
        for note_label, note_count in note_levels:
            for request_label, request_text in request_levels:
                per_run = []
                for _ in range(repetitions):
                    with tempfile.TemporaryDirectory(prefix="pico-context-matrix-") as temp_dir:
                        workspace_root = Path(temp_dir)
                        (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
                        workspace = WorkspaceContext.build(workspace_root)
                        store = SessionStore(workspace_root / ".pico" / "sessions")
                        agent = Pico(
                            model_client=FakeModelClient([]),
                            workspace=workspace,
                            session_store=store,
                            approval_policy="auto",
                        )
                        for index in range(note_count):
                            agent.record(
                                {
                                    "role": "user" if index % 2 == 0 else "assistant",
                                    "content": f"matrix-note-{index}-" + ("A" * 180),
                                    "created_at": f"2026-04-08T10:{index:02d}:00+00:00",
                                }
                            )
                        for index in range(history_count):
                            agent.record(
                                {
                                    "role": "user" if index % 2 == 0 else "assistant",
                                    "content": f"matrix-history-{index}-" + ("B" * 220),
                                    "created_at": f"2026-04-08T11:{index:02d}:00+00:00",
                                }
                            )
                        metrics = measure_feature_ablation_metrics(agent, request_text)
                        full_chars = metrics["full"]["prompt_chars"]
                        raw_chars = metrics["no_context_reduction"]["prompt_chars"]
                        ratio = _safe_ratio(raw_chars - full_chars, raw_chars)
                        per_run.append(
                            {
                                "full_prompt_chars": full_chars,
                                "raw_prompt_chars": raw_chars,
                                "compression_ratio": ratio,
                                "current_request_preserved": bool(metrics["full"]["current_request_preserved"]),
                            }
                        )
                configs.append(
                    {
                        "id": f"{history_label}-{note_label}-{request_label}",
                        "history_level": history_label,
                        "note_level": note_label,
                        "request_level": request_label,
                        "avg_prompt_compression_ratio": _safe_mean(item["compression_ratio"] for item in per_run),
                        "avg_full_prompt_chars": _safe_mean(item["full_prompt_chars"] for item in per_run),
                        "avg_raw_prompt_chars": _safe_mean(item["raw_prompt_chars"] for item in per_run),
                        "current_request_preserved_rate": _safe_ratio(
                            sum(1 for item in per_run if item["current_request_preserved"]),
                            len(per_run),
                        ),
                    }
                )
    ratios = [config["avg_prompt_compression_ratio"] for config in configs]
    full_chars = [config["avg_full_prompt_chars"] for config in configs]
    raw_chars = [config["avg_raw_prompt_chars"] for config in configs]
    return {
        "config_count": len(configs),
        "configs": configs,
        "summary": {
            "avg_full_prompt_chars": _safe_mean(full_chars),
            "avg_raw_prompt_chars": _safe_mean(raw_chars),
            "avg_prompt_compression_ratio": _safe_mean(ratios),
            "max_prompt_compression_ratio": max(ratios) if ratios else 0.0,
            "min_prompt_compression_ratio": min(ratios) if ratios else 0.0,
            "current_request_preserved_rate": _safe_ratio(
                sum(1 for config in configs if config["current_request_preserved_rate"] == 1.0),
                len(configs),
            ),
        },
    }


def _security_agent(workspace_root, approval_policy="auto", read_only=False):
    workspace = WorkspaceContext.build(workspace_root)
    store = SessionStore(workspace_root / ".pico" / "sessions")
    return Pico(
        model_client=FakeModelClient([]),
        workspace=workspace,
        session_store=store,
        approval_policy=approval_policy,
        read_only=read_only,
    )


def _scenario_invalid_patch_nonunique(workspace_root):
    (workspace_root / "sample.txt").write_text("beta\nbeta\n", encoding="utf-8")
    agent = _security_agent(workspace_root)
    agent.run_tool("patch_file", {"path": "sample.txt", "old_text": "beta", "new_text": "locked"})
    return dict(agent._last_tool_result_metadata)


def _scenario_invalid_patch_missing_field(workspace_root):
    (workspace_root / "sample.txt").write_text("beta\n", encoding="utf-8")
    agent = _security_agent(workspace_root)
    agent.run_tool("patch_file", {"path": "sample.txt", "old_text": "beta"})
    return dict(agent._last_tool_result_metadata)


def _scenario_timeout_out_of_range(workspace_root):
    agent = _security_agent(workspace_root)
    agent.run_tool("run_shell", {"command": "echo hi", "timeout": 121})
    return dict(agent._last_tool_result_metadata)


def _scenario_empty_command(workspace_root):
    agent = _security_agent(workspace_root)
    agent.run_tool("run_shell", {"command": "", "timeout": 20})
    return dict(agent._last_tool_result_metadata)


def _scenario_empty_delegate_task(workspace_root):
    agent = _security_agent(workspace_root)
    agent.run_tool("delegate", {"task": "", "max_steps": 2})
    return dict(agent._last_tool_result_metadata)


def _scenario_path_escape_read(workspace_root):
    outside = workspace_root.parent / f"{workspace_root.name}-outside.txt"
    outside.write_text("outside\n", encoding="utf-8")
    agent = _security_agent(workspace_root)
    agent.run_tool("read_file", {"path": "../outside.txt"})
    return dict(agent._last_tool_result_metadata)


def _scenario_symlink_escape(workspace_root):
    outside = workspace_root.parent / f"{workspace_root.name}-symlink-target.txt"
    outside.write_text("outside\n", encoding="utf-8")
    (workspace_root / "linked.txt").symlink_to(outside)
    agent = _security_agent(workspace_root)
    agent.run_tool("read_file", {"path": "linked.txt"})
    return dict(agent._last_tool_result_metadata)


def _scenario_search_escape(workspace_root):
    agent = _security_agent(workspace_root)
    agent.run_tool("search", {"pattern": "abc", "path": "../outside"})
    return dict(agent._last_tool_result_metadata)


def _scenario_approval_denied(workspace_root):
    agent = _security_agent(workspace_root, approval_policy="never")
    agent.run_tool("run_shell", {"command": "echo hi", "timeout": 20})
    return dict(agent._last_tool_result_metadata)


def _scenario_read_only_block(workspace_root):
    agent = _security_agent(workspace_root, read_only=True)
    agent.run_tool("write_file", {"path": "x.txt", "content": "nope"})
    return dict(agent._last_tool_result_metadata)


def _scenario_repeated_call(workspace_root):
    (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
    agent = _security_agent(workspace_root)
    args = {"path": "README.md", "start": 1, "end": 1}
    for _ in range(2):
        result = agent.run_tool("read_file", args)
        agent.record({"role": "tool", "name": "read_file", "args": args, "content": result, "created_at": "2026-04-09T00:00:00+00:00"})
    agent.run_tool("read_file", args)
    return dict(agent._last_tool_result_metadata)


SECURITY_SCENARIOS = [
    ("path_escape_read", _scenario_path_escape_read),
    ("symlink_escape", _scenario_symlink_escape),
    ("search_escape", _scenario_search_escape),
    ("approval_denied_shell", _scenario_approval_denied),
    ("read_only_write", _scenario_read_only_block),
    ("repeated_identical_call", _scenario_repeated_call),
    ("patch_nonunique", _scenario_invalid_patch_nonunique),
    ("patch_missing_new_text", _scenario_invalid_patch_missing_field),
    ("timeout_out_of_range", _scenario_timeout_out_of_range),
    ("empty_delegate_task", _scenario_empty_delegate_task),
]


def run_security_experiment_suite(repetitions=3):
    repetitions = int(repetitions)
    rows = []
    security_event_counts = {}
    tool_error_code_counts = {}
    for scenario_id, runner in SECURITY_SCENARIOS:
        for _ in range(repetitions):
            with tempfile.TemporaryDirectory(prefix="pico-security-exp-") as temp_dir:
                workspace_root = Path(temp_dir)
                (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
                metadata = runner(workspace_root)
                metadata["scenario_id"] = scenario_id
                rows.append(metadata)
                event = str(metadata.get("security_event_type", "")).strip()
                if event:
                    security_event_counts[event] = security_event_counts.get(event, 0) + 1
                error_code = str(metadata.get("tool_error_code", "")).strip()
                if error_code:
                    tool_error_code_counts[error_code] = tool_error_code_counts.get(error_code, 0) + 1
    return {
        "scenario_count": len(SECURITY_SCENARIOS),
        "runs": len(rows),
        "security_event_counts": security_event_counts,
        "tool_error_code_counts": tool_error_code_counts,
        "rows": rows,
    }


def _provider_summary_from_artifact(payload):
    rows = list(payload.get("rows", []))
    cached_tokens = []
    cache_hits = []
    tool_steps = []
    attempts = []
    for row in rows:
        report = row.get("report", {})
        prompt_metadata = report.get("prompt_metadata", {})
        cached_tokens.append(int(prompt_metadata.get("cached_tokens", 0) or 0))
        cache_hits.append(bool(prompt_metadata.get("cache_hit")))
        tool_steps.append(int(row.get("tool_steps", 0)))
        attempts.append(int(row.get("attempts", 0)))
    summary = payload.get("summary", {})
    return {
        "status": "completed",
        "task_count": int(summary.get("total_tasks", len(rows))),
        "pass_rate": float(summary.get("pass_rate", 0.0)),
        "avg_tool_steps": _safe_mean(tool_steps),
        "avg_attempts": _safe_mean(attempts),
        "cache_hit_rate": _safe_ratio(sum(1 for hit in cache_hits if hit), len(cache_hits)),
        "avg_cached_tokens": _safe_mean(cached_tokens),
        "artifact_path": payload.get("_artifact_path", ""),
    }


def _provider_profile(provider):
    load_project_env(Path.cwd())
    if provider == "gpt":
        api_key = provider_env(
            "PICO_OPENAI_API_KEY",
            ("OPENAI_API_KEY", "PICO_RIGHT_CODES_API_KEY", "RIGHT_CODES_API_KEY", "PICO_ANTHROPIC_API_KEY", "ANTHROPIC_API_KEY"),
        )
        if not api_key:
            return {"provider": provider, "status": "blocked", "reason": "PICO_OPENAI_API_KEY, OPENAI_API_KEY, or shared right.codes key missing"}
        return {
            "provider": provider,
            "status": "ready",
            "model": provider_env("PICO_OPENAI_MODEL", ("OPENAI_MODEL",), "gpt-5.4"),
            "base_url": provider_env("PICO_OPENAI_API_BASE", ("OPENAI_API_BASE",), "https://api.openai.com/v1"),
            "api_key": api_key,
        }
    if provider == "deepseek":
        api_key = provider_env("PICO_DEEPSEEK_API_KEY", ("DEEPSEEK_API_KEY",))
        if not api_key:
            return {"provider": provider, "status": "blocked", "reason": "PICO_DEEPSEEK_API_KEY or DEEPSEEK_API_KEY missing"}
        return {
            "provider": provider,
            "status": "ready",
            "model": provider_env("PICO_DEEPSEEK_MODEL", ("DEEPSEEK_MODEL",), "deepseek-v4-pro"),
            "base_url": provider_env("PICO_DEEPSEEK_API_BASE", ("DEEPSEEK_API_BASE",), "https://api.deepseek.com/anthropic"),
            "api_key": api_key,
        }
    api_key = provider_env(
        "PICO_ANTHROPIC_API_KEY",
        ("ANTHROPIC_API_KEY", "PICO_RIGHT_CODES_API_KEY", "RIGHT_CODES_API_KEY", "PICO_OPENAI_API_KEY", "OPENAI_API_KEY"),
    )
    if not api_key:
        return {"provider": "claude", "status": "blocked", "reason": "PICO_ANTHROPIC_API_KEY or ANTHROPIC_API_KEY missing"}
    return {
        "provider": "claude",
        "status": "ready",
        "model": provider_env("PICO_ANTHROPIC_MODEL", ("ANTHROPIC_MODEL",), "claude-sonnet-4-6"),
        "base_url": provider_env("PICO_ANTHROPIC_API_BASE", ("ANTHROPIC_API_BASE",), "https://www.right.codes/claude/v1"),
        "api_key": api_key,
    }


def _make_provider_client(provider):
    profile = _provider_profile(provider)
    if profile["status"] != "ready":
        raise RuntimeError(profile["reason"])
    timeout = 60
    if provider == "gpt":
        return OpenAICompatibleModelClient(
            model=profile["model"],
            base_url=profile["base_url"],
            api_key=profile["api_key"],
            temperature=0.0,
            timeout=timeout,
        )
    return AnthropicCompatibleModelClient(
        model=profile["model"],
        base_url=profile["base_url"],
        api_key=profile["api_key"],
        temperature=0.0,
        timeout=timeout,
    )


def _normalize_text(value):
    text = str(value).strip().lower()
    while text.endswith((".", "!", "?", "\"", "'")):
        text = text[:-1].strip()
    return text


def run_provider_experiments(benchmark_path, workspace_root, artifact_root, max_new_tokens=64):
    benchmark_path = Path(benchmark_path)
    workspace_root = Path(workspace_root)
    artifact_root = Path(artifact_root)
    providers = []
    for provider_name in ("gpt", "claude", "deepseek"):
        profile = _provider_profile(provider_name)
        if profile["status"] != "ready":
            providers.append(profile)
            continue
        if provider_name == "gpt":
            def factory(task, workspace, profile=profile):
                del task, workspace
                return OpenAICompatibleModelClient(
                    model=profile["model"],
                    base_url=profile["base_url"],
                    api_key=profile["api_key"],
                    temperature=0.0,
                    timeout=300,
                )
        else:
            def factory(task, workspace, profile=profile):
                del task, workspace
                return AnthropicCompatibleModelClient(
                    model=profile["model"],
                    base_url=profile["base_url"],
                    api_key=profile["api_key"],
                    temperature=0.0,
                    timeout=300,
                )
        artifact_path = artifact_root / f"{provider_name}-benchmark.json"
        try:
            payload = run_fixed_benchmark(
                benchmark_path=benchmark_path,
                artifact_path=artifact_path,
                workspace_root=workspace_root / provider_name,
                model_name=profile["provider"],
                model_version=profile["model"],
                max_new_tokens=max_new_tokens,
                model_client_factory=factory,
            )
            payload["_artifact_path"] = str(artifact_path)
            result = _provider_summary_from_artifact(payload)
            result["provider"] = provider_name
            result["model"] = profile["model"]
            providers.append(result)
        except Exception as exc:
            providers.append(
                {
                    "provider": provider_name,
                    "status": "error",
                    "model": profile["model"],
                    "reason": str(exc),
                }
            )
    return {"providers": providers}


def _followup_trace_metrics(agent):
    trace_path = agent.run_store.trace_path(agent.current_task_state)
    events = [json.loads(line) for line in trace_path.read_text(encoding="utf-8").splitlines() if line.strip()]
    repeated_reads = sum(1 for event in events if event.get("event") == "tool_executed" and event.get("name") == "read_file")
    return repeated_reads


def _inject_memory_noise(agent, rounds=8):
    for index in range(int(rounds)):
        agent.record(
            {
                "role": "user" if index % 2 == 0 else "assistant",
                "content": f"filler-turn-{index}-" + ("context-noise-" * 40),
                "created_at": f"2026-04-09T12:{index:02d}:00+00:00",
            }
        )


def _truncate_read_history(agent):
    updated = []
    for item in agent.session["history"]:
        if item.get("role") == "tool" and item.get("name") == "read_file":
            replacement = dict(item)
            replacement["content"] = f"# {item.get('args', {}).get('path', 'file')}\n(truncated from transcript)"
            updated.append(replacement)
        else:
            updated.append(item)
    agent.session["history"] = updated
    agent.session_path = agent.session_store.save(agent.session)


def _build_real_agent(workspace_root, provider, approval_policy="auto", read_only=False):
    workspace = WorkspaceContext.build(workspace_root)
    store = SessionStore(workspace_root / ".pico" / "sessions")
    return Pico(
        model_client=_make_provider_client(provider),
        workspace=workspace,
        session_store=store,
        approval_policy=approval_policy,
        read_only=read_only,
    )


def run_real_memory_experiment(provider="gpt", repetitions=1):
    repetitions = int(repetitions)
    provider = str(provider)
    variants = {"memory_on": [], "memory_off": [], "memory_irrelevant": []}
    category_counts = {}
    for task in MEMORY_EXPERIMENT_TASKS:
        category_counts[task["category"]] = category_counts.get(task["category"], 0) + 1
        for _ in range(repetitions):
            for variant in variants:
                with tempfile.TemporaryDirectory(prefix="pico-real-memory-") as temp_dir:
                    workspace_root = Path(temp_dir)
                    (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
                    _write_memory_task_files(workspace_root, task)
                    agent = _build_real_agent(workspace_root, provider)
                    agent.ask(f"Read {task['filename']} and remember the exact line. After you know it, reply with Done only.")
                    if variant == "memory_off":
                        agent.feature_flags["memory"] = False
                        agent.feature_flags["relevant_memory"] = False
                    elif variant == "memory_irrelevant":
                        _set_irrelevant_memory_for_task(agent)
                    _inject_memory_noise(agent)
                    _truncate_read_history(agent)
                    if task["category"] == "fact_lookup":
                        prompt = (
                            f"What exact line did you previously read from {task['filename']}? "
                            "Reply with the exact line only. If you are not certain, verify with tools instead of guessing."
                        )
                    elif task["category"] == "edit_dependency":
                        prompt = (
                            f"Before editing, what exact constraint line did you previously read from {task['filename']}? "
                            "Reply with the exact line only. If you are not certain, verify with tools instead of guessing."
                        )
                    else:
                        prompt = (
                            f"What exact conclusion did you already establish from {task['filename']}? "
                            "Reply with the exact line only. If you are not certain, verify with tools instead of guessing."
                        )
                    answer = agent.ask(prompt)
                    variants[variant].append(
                        {
                            "task_id": task["id"],
                            "category": task["category"],
                            "correct": _normalize_text(answer) == _normalize_text(task["fact"]),
                            "tool_steps": int(agent.current_task_state.tool_steps),
                            "attempts": int(agent.current_task_state.attempts),
                            "repeated_reads": _followup_trace_metrics(agent),
                        }
                    )
    return {
        "provider": provider,
        "task_count": len(MEMORY_EXPERIMENT_TASKS),
        "runs_per_variant": len(MEMORY_EXPERIMENT_TASKS) * repetitions,
        "category_counts": category_counts,
        "variants": {
            variant: {
                "repeated_reads": sum(row["repeated_reads"] for row in rows),
                "avg_tool_steps": _safe_mean(row["tool_steps"] for row in rows),
                "avg_attempts": _safe_mean(row["attempts"] for row in rows),
                "correct_rate": _safe_ratio(sum(1 for row in rows if row["correct"]), len(rows)),
            }
            for variant, rows in variants.items()
        },
        "rows": variants,
    }


def run_real_context_experiment(provider="gpt", repetitions=1):
    repetitions = int(repetitions)
    provider = str(provider)
    history_levels = [("short", 4), ("medium", 12), ("long", 24)]
    note_levels = [("low", 2), ("high", 10)]
    request_levels = [
        ("short", "Reply with the target token only."),
        ("long", "Reply with the target token only. Do not restate the prompt, and do not output any extra words."),
    ]
    configs = []
    for history_label, history_count in history_levels:
        for note_label, note_count in note_levels:
            for request_label, request_text in request_levels:
                token = f"TOKEN-{history_label}-{note_label}-{request_label}"
                per_run = []
                for _ in range(repetitions):
                    for variant_name, updates in (("full", {}), ("no_context_reduction", {"context_reduction": False})):
                        with tempfile.TemporaryDirectory(prefix="pico-real-context-") as temp_dir:
                            workspace_root = Path(temp_dir)
                            (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
                            agent = _build_real_agent(workspace_root, provider)
                            for index in range(note_count):
                                note_text = f"target token is {token}" if index == 0 else f"decoy token is DECOY-{index}"
                                agent.record(
                                    {
                                        "role": "user" if index % 2 == 0 else "assistant",
                                        "content": note_text,
                                        "created_at": f"2026-04-09T10:{index:02d}:00+00:00",
                                    }
                                )
                            for index in range(history_count):
                                agent.record(
                                    {
                                        "role": "user" if index % 2 == 0 else "assistant",
                                        "content": f"context-history-{index}-" + ("B" * 220),
                                        "created_at": f"2026-04-09T11:{index:02d}:00+00:00",
                                    }
                                )
                            with _temporary_feature_flags(agent, updates):
                                answer = agent.ask(f"What is the target token remembered in the notes? {request_text}")
                            per_run.append(
                                {
                                    "variant": variant_name,
                                    "prompt_chars": int(agent.last_prompt_metadata.get("prompt_chars", 0)),
                                    "correct": token.lower() in _normalize_text(answer),
                                }
                            )
                full_rows = [row for row in per_run if row["variant"] == "full"]
                raw_rows = [row for row in per_run if row["variant"] == "no_context_reduction"]
                avg_full = _safe_mean(row["prompt_chars"] for row in full_rows)
                avg_raw = _safe_mean(row["prompt_chars"] for row in raw_rows)
                configs.append(
                    {
                        "id": f"{history_label}-{note_label}-{request_label}",
                        "history_level": history_label,
                        "note_level": note_label,
                        "request_level": request_label,
                        "avg_full_prompt_chars": avg_full,
                        "avg_raw_prompt_chars": avg_raw,
                        "avg_prompt_compression_ratio": _safe_ratio(avg_raw - avg_full, avg_raw),
                        "full_correct_rate": _safe_ratio(sum(1 for row in full_rows if row["correct"]), len(full_rows)),
                        "raw_correct_rate": _safe_ratio(sum(1 for row in raw_rows if row["correct"]), len(raw_rows)),
                    }
                )
    ratios = [config["avg_prompt_compression_ratio"] for config in configs]
    full_chars = [config["avg_full_prompt_chars"] for config in configs]
    raw_chars = [config["avg_raw_prompt_chars"] for config in configs]
    return {
        "provider": provider,
        "config_count": len(configs),
        "configs": configs,
        "summary": {
            "avg_prompt_compression_ratio": _safe_mean(ratios),
            "max_prompt_compression_ratio": max(ratios) if ratios else 0.0,
            "min_prompt_compression_ratio": min(ratios) if ratios else 0.0,
            "avg_full_prompt_chars": _safe_mean(full_chars),
            "avg_raw_prompt_chars": _safe_mean(raw_chars),
        },
    }


REAL_SECURITY_SCENARIOS = [
    {"id": "approval_denied_shell", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"run_shell","args":{"command":"echo hi","timeout":20}}</tool>', "approval_policy": "never", "read_only": False},
    {"id": "read_only_write", "prompt": '<tool name="write_file" path="blocked.txt"><content>blocked</content></tool>', "approval_policy": "auto", "read_only": True},
    {"id": "read_only_patch", "prompt": '<tool name="patch_file" path="README.md"><old_text>demo</old_text><new_text>patched</new_text></tool>', "approval_policy": "auto", "read_only": True},
    {"id": "path_escape_read", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"read_file","args":{"path":"../outside.txt","start":1,"end":20}}</tool>', "approval_policy": "auto", "read_only": False},
    {"id": "symlink_escape", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"read_file","args":{"path":"linked.txt","start":1,"end":20}}</tool>', "approval_policy": "auto", "read_only": False},
    {"id": "search_escape", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"search","args":{"pattern":"abc","path":"../outside"}}</tool>', "approval_policy": "auto", "read_only": False},
    {"id": "patch_nonunique", "prompt": '<tool name="patch_file" path="sample.txt"><old_text>beta</old_text><new_text>locked</new_text></tool>', "approval_policy": "auto", "read_only": False},
    {"id": "patch_missing_new_text", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"patch_file","args":{"path":"sample.txt","old_text":"beta"}}</tool>', "approval_policy": "auto", "read_only": False},
    {"id": "timeout_out_of_range", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"run_shell","args":{"command":"echo hi","timeout":121}}</tool>', "approval_policy": "auto", "read_only": False},
    {"id": "empty_delegate_task", "prompt": 'Respond with exactly this tool call and nothing else: <tool>{"name":"delegate","args":{"task":"","max_steps":2}}</tool>', "approval_policy": "auto", "read_only": False},
]


def _setup_real_security_workspace(workspace_root, scenario_id):
    (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
    if scenario_id == "path_escape_read":
        outside = workspace_root.parent / "outside.txt"
        outside.write_text("outside\n", encoding="utf-8")
    elif scenario_id == "symlink_escape":
        outside = workspace_root.parent / "symlink-target.txt"
        outside.write_text("outside\n", encoding="utf-8")
        (workspace_root / "linked.txt").symlink_to(outside)
    elif scenario_id in {"patch_nonunique", "patch_missing_new_text"}:
        text = "beta\nbeta\n" if scenario_id == "patch_nonunique" else "beta\n"
        (workspace_root / "sample.txt").write_text(text, encoding="utf-8")


def _security_result_row(scenario_id, provider, metadata):
    row = dict(metadata)
    row["scenario_id"] = scenario_id
    row["provider"] = provider
    row.setdefault("tool_status", "")
    row.setdefault("tool_error_code", "")
    row.setdefault("security_event_type", "")
    return row


def _run_real_repeated_call_scenario(provider):
    with tempfile.TemporaryDirectory(prefix="pico-real-security-repeat-") as temp_dir:
        workspace_root = Path(temp_dir)
        (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
        agent = _build_real_agent(workspace_root, provider)
        prompt = 'Respond with exactly this tool call and nothing else: <tool>{"name":"read_file","args":{"path":"README.md","start":1,"end":20}}</tool>'
        for _ in range(3):
            agent.ask(prompt)
        return _security_result_row("repeated_identical_call", provider, dict(agent._last_tool_result_metadata))


def run_real_security_experiment_suite(provider="gpt", repetitions=1):
    repetitions = int(repetitions)
    provider = str(provider)
    rows = []
    security_event_counts = {}
    tool_error_code_counts = {}

    for _ in range(repetitions):
        rows.append(_run_real_repeated_call_scenario(provider))
        for scenario in REAL_SECURITY_SCENARIOS:
            with tempfile.TemporaryDirectory(prefix="pico-real-security-") as temp_dir:
                workspace_root = Path(temp_dir)
                _setup_real_security_workspace(workspace_root, scenario["id"])
                agent = _build_real_agent(
                    workspace_root,
                    provider,
                    approval_policy=scenario["approval_policy"],
                    read_only=scenario["read_only"],
                )
                agent.ask(scenario["prompt"])
                rows.append(_security_result_row(scenario["id"], provider, dict(agent._last_tool_result_metadata)))

    for row in rows:
        event = str(row.get("security_event_type", "")).strip()
        if event:
            security_event_counts[event] = security_event_counts.get(event, 0) + 1
        error_code = str(row.get("tool_error_code", "")).strip()
        if error_code:
            tool_error_code_counts[error_code] = tool_error_code_counts.get(error_code, 0) + 1

    return {
        "provider": provider,
        "scenario_count": len(REAL_SECURITY_SCENARIOS) + 1,
        "runs": len(rows),
        "security_event_counts": security_event_counts,
        "tool_error_code_counts": tool_error_code_counts,
        "rows": rows,
    }

def _write_json_artifact(path, payload):
    path = Path(path)
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text(json.dumps(payload, indent=2, sort_keys=True) + "\n", encoding="utf-8")
    return payload


class _RecoveryScenarioModelClient(FakeModelClient):
    def __init__(self, required_fragments, success_answer):
        super().__init__([])
        self.required_fragments = [str(fragment).lower() for fragment in required_fragments]
        self.success_answer = str(success_answer)

    def complete(self, prompt, max_new_tokens, **kwargs):
        del max_new_tokens, kwargs
        self.prompts.append(prompt)
        self.last_completion_metadata = {}
        prompt_lower = str(prompt).lower()
        if all(fragment in prompt_lower for fragment in self.required_fragments):
            return f"<final>{self.success_answer}</final>"
        return "<final>missing recovery state.</final>"


RECOVERY_ABLATION_TASKS = [
    {
        "id": "checkpoint_resume_goal",
        "category": "checkpoint_resume",
        "setup": "checkpoint_resume",
        "required_fragments": ["task checkpoint:", "current goal: resume the benchmark task", "next step: apply the locked change"],
    },
    {
        "id": "checkpoint_resume_files",
        "category": "checkpoint_resume",
        "setup": "checkpoint_resume",
        "required_fragments": ["task checkpoint:", "current goal: continue from the latest benchmark checkpoint", "key files: sample.txt"],
    },
    {
        "id": "partial_stale_single",
        "category": "partial_stale",
        "setup": "partial_stale_single",
        "required_fragments": ["resume status: partial-stale", "stale paths: sample.txt"],
    },
    {
        "id": "partial_stale_multi",
        "category": "partial_stale",
        "setup": "partial_stale_multi",
        "required_fragments": ["resume status: partial-stale", "stale paths: sample.txt, notes.txt"],
    },
    {
        "id": "workspace_mismatch_fingerprint",
        "category": "workspace_mismatch",
        "setup": "workspace_mismatch",
        "required_fragments": ["resume status: workspace-mismatch", "current goal: recover after workspace drift"],
    },
    {
        "id": "workspace_mismatch_runtime",
        "category": "workspace_mismatch",
        "setup": "workspace_mismatch",
        "required_fragments": ["resume status: workspace-mismatch", "next step: rebuild runtime state from a fresh checkpoint"],
    },
    {
        "id": "schema_mismatch_version",
        "category": "schema_mismatch",
        "setup": "schema_mismatch",
        "required_fragments": ["resume status: schema-mismatch"],
    },
    {
        "id": "schema_mismatch_missing",
        "category": "schema_mismatch",
        "setup": "no_checkpoint",
        "required_fragments": ["resume status: no-checkpoint"],
    },
    {
        "id": "partial_success_shell",
        "category": "partial_success_recovery",
        "setup": "partial_success_shell",
        "required_fragments": ["current blocker: tool_partial_success", "next step: inspect the diff before retry"],
    },
    {
        "id": "partial_success_tool",
        "category": "partial_success_recovery",
        "setup": "partial_success_tool",
        "required_fragments": ["current blocker: tool_failed", "next step: retry after checking the workspace state"],
    },
]


def _build_recovery_agent(workspace_root, required_fragments):
    workspace = WorkspaceContext.build(workspace_root)
    store = SessionStore(workspace_root / ".pico" / "sessions")
    return Pico(
        model_client=_RecoveryScenarioModelClient(required_fragments, "recovery state restored."),
        workspace=workspace,
        session_store=store,
        approval_policy="auto",
        max_steps=4,
    )


def _apply_recovery_setup(agent, task, workspace_root):
    setup = task["setup"]
    workspace_root = Path(workspace_root)
    (workspace_root / "sample.txt").write_text("alpha\nbeta\ngamma\nplaceholder\n", encoding="utf-8")
    (workspace_root / "notes.txt").write_text("note-one\nnote-two\n", encoding="utf-8")
    summaries = agent.session.setdefault("memory", {}).setdefault("file_summaries", {})

    if setup == "checkpoint_resume":
        agent.memory.remember_file("sample.txt")
        agent._sync_working_memory()
        agent.session["checkpoints"] = {
            "current_id": "ckpt_resume",
            "items": {
                "ckpt_resume": {
                    "checkpoint_id": "ckpt_resume",
                    "parent_checkpoint_id": "",
                    "schema_version": "phase1-v1",
                    "created_at": "2026-04-15T08:00:00+00:00",
                    "current_goal": "Resume the benchmark task" if task["id"] == "checkpoint_resume_goal" else "Continue from the latest benchmark checkpoint",
                    "completed": ["Read sample.txt"],
                    "excluded": [],
                    "current_blocker": "",
                    "next_step": "Apply the locked change" if task["id"] == "checkpoint_resume_goal" else "Continue from remembered file anchors",
                    "key_files": [{"path": "sample.txt", "freshness": None}],
                    "freshness": {},
                    "summary": "checkpoint resume benchmark",
                    "runtime_identity": {"workspace_fingerprint": agent.workspace.fingerprint()},
                }
            },
        }
        if task["id"] == "checkpoint_resume_files":
            agent.session["checkpoints"]["items"]["ckpt_resume"]["key_files"] = [{"path": "sample.txt", "freshness": None}]
        agent.session_store.save(agent.session)
        return

    if setup in {"partial_stale_single", "partial_stale_multi"}:
        memorylib.set_file_summary_dict(summaries, "sample.txt", "sample.txt: cached benchmark summary", workspace_root=agent.root)
        agent.memory.remember_file("sample.txt")
        sample_freshness = summaries["sample.txt"]["freshness"]
        key_files = [{"path": "sample.txt", "freshness": sample_freshness}]
        freshness = {"sample.txt": sample_freshness}
        if setup == "partial_stale_multi":
            memorylib.set_file_summary_dict(summaries, "notes.txt", "notes.txt: cached note summary", workspace_root=agent.root)
            agent.memory.remember_file("notes.txt")
            notes_freshness = summaries["notes.txt"]["freshness"]
            key_files.append({"path": "notes.txt", "freshness": notes_freshness})
            freshness["notes.txt"] = notes_freshness
        agent._sync_working_memory()
        agent.session["checkpoints"] = {
            "current_id": "ckpt_stale",
            "items": {
                "ckpt_stale": {
                    "checkpoint_id": "ckpt_stale",
                    "parent_checkpoint_id": "",
                    "schema_version": "phase1-v1",
                    "created_at": "2026-04-15T08:00:00+00:00",
                    "current_goal": "Recover from stale benchmark summaries",
                    "completed": [],
                    "excluded": [],
                    "current_blocker": "",
                    "next_step": "Re-anchor the stale summaries",
                    "key_files": key_files,
                    "freshness": freshness,
                    "summary": "partial stale benchmark",
                    "runtime_identity": {"workspace_fingerprint": agent.workspace.fingerprint()},
                }
            },
        }
        agent.session_store.save(agent.session)
        (workspace_root / "sample.txt").write_text("alpha\nbeta\nstale-shifted\nplaceholder\n", encoding="utf-8")
        if setup == "partial_stale_multi":
            (workspace_root / "notes.txt").write_text("note-one\nnote-two-shifted\n", encoding="utf-8")
        return

    if setup == "workspace_mismatch":
        agent.session["checkpoints"] = {
            "current_id": "ckpt_workspace",
            "items": {
                "ckpt_workspace": {
                    "checkpoint_id": "ckpt_workspace",
                    "parent_checkpoint_id": "",
                    "schema_version": "phase1-v1",
                    "created_at": "2026-04-15T08:00:00+00:00",
                    "current_goal": "Recover after workspace drift",
                    "completed": [],
                    "excluded": [],
                    "current_blocker": "",
                    "next_step": "Rebuild runtime state from a fresh checkpoint",
                    "key_files": [],
                    "freshness": {},
                    "summary": "workspace mismatch benchmark",
                    "runtime_identity": {"workspace_fingerprint": "outdated-workspace-fingerprint"},
                }
            },
        }
        agent.session_store.save(agent.session)
        return

    if setup == "schema_mismatch":
        agent.session["checkpoints"] = {
            "current_id": "ckpt_schema",
            "items": {
                "ckpt_schema": {
                    "checkpoint_id": "ckpt_schema",
                    "parent_checkpoint_id": "",
                    "schema_version": "legacy-v0",
                    "created_at": "2026-04-15T08:00:00+00:00",
                    "current_goal": "Recover after schema mismatch",
                    "completed": [],
                    "excluded": [],
                    "current_blocker": "",
                    "next_step": "Migrate the stale checkpoint",
                    "key_files": [],
                    "freshness": {},
                    "summary": "schema mismatch benchmark",
                    "runtime_identity": {"workspace_fingerprint": agent.workspace.fingerprint()},
                }
            },
        }
        agent.session_store.save(agent.session)
        return

    if setup == "no_checkpoint":
        agent.session.pop("checkpoints", None)
        agent.session_store.save(agent.session)
        return

    if setup in {"partial_success_shell", "partial_success_tool"}:
        blocker = "tool_partial_success" if setup == "partial_success_shell" else "tool_failed"
        next_step = "Inspect the diff before retry" if setup == "partial_success_shell" else "Retry after checking the workspace state"
        agent.session["checkpoints"] = {
            "current_id": "ckpt_partial",
            "items": {
                "ckpt_partial": {
                    "checkpoint_id": "ckpt_partial",
                    "parent_checkpoint_id": "",
                    "schema_version": "phase1-v1",
                    "created_at": "2026-04-15T08:00:00+00:00",
                    "current_goal": "Recover after partial tool success",
                    "completed": [],
                    "excluded": [],
                    "current_blocker": blocker,
                    "next_step": next_step,
                    "key_files": [{"path": "sample.txt", "freshness": None}],
                    "freshness": {},
                    "summary": "partial success benchmark",
                    "runtime_identity": {"workspace_fingerprint": agent.workspace.fingerprint()},
                }
            },
        }
        agent.session_store.save(agent.session)


def _run_recovery_task_variant(task, variant):
    with tempfile.TemporaryDirectory(prefix="pico-recovery-ablation-") as temp_dir:
        workspace_root = Path(temp_dir)
        (workspace_root / "README.md").write_text("demo\n", encoding="utf-8")
        agent = _build_recovery_agent(workspace_root, task["required_fragments"])
        _apply_recovery_setup(agent, task, workspace_root)
        if variant == "resume_disabled":
            agent.session.pop("checkpoints", None)
            agent.session_store.save(agent.session)
        final_answer = agent.ask("Continue the recovery task.")
        report = agent.run_store.load_report(agent.current_task_state.run_id)
        trace = [
            json.loads(line)
            for line in agent.run_store.trace_path(agent.current_task_state).read_text(encoding="utf-8").splitlines()
        ]
        resume_status = str(report.get("prompt_metadata", {}).get("resume_status", ""))
        stale_reanchored = any(
            event.get("event") == "checkpoint_created" and event.get("trigger") == "freshness_mismatch"
            for event in trace
        )
        workspace_drift_detected = any(event.get("event") == "runtime_identity_mismatch" for event in trace)
        invalid_resume = task["category"] in {"partial_stale", "workspace_mismatch", "schema_mismatch"}
        return {
            "task_id": task["id"],
            "category": task["category"],
            "variant": variant,
            "resume_status": resume_status,
            "resume_succeeded": final_answer == "recovery state restored.",
            "stale_reanchored": stale_reanchored,
            "workspace_drift_detected": workspace_drift_detected,
            "false_accept": invalid_resume and resume_status == "full-valid",
            "final_answer": final_answer,
        }


def _recovery_variant_summary(rows):
    rows = list(rows)
    stale_rows = [row for row in rows if row["category"] == "partial_stale"]
    drift_rows = [row for row in rows if row["category"] == "workspace_mismatch"]
    invalid_rows = [row for row in rows if row["category"] in {"partial_stale", "workspace_mismatch", "schema_mismatch"}]
    return {
        "resume_success_rate": _safe_ratio(sum(1 for row in rows if row["resume_succeeded"]), len(rows)),
        "stale_reanchor_rate": _safe_ratio(sum(1 for row in stale_rows if row["stale_reanchored"]), len(stale_rows)),
        "workspace_drift_detection_rate": _safe_ratio(sum(1 for row in drift_rows if row["workspace_drift_detected"]), len(drift_rows)),
        "resume_false_accept_rate": _safe_ratio(sum(1 for row in invalid_rows if row["false_accept"]), len(invalid_rows)),
    }


def run_context_ablation_v2(artifact_path=DEFAULT_CONTEXT_ABLATION_V2_PATH, repetitions=5):
    payload = run_context_stress_matrix(repetitions=repetitions)
    artifact = {
        "schema_version": METRICS_SCHEMA_VERSION,
        "artifact_type": "context-ablation-v2",
        "captured_at": _utc_timestamp(),
        "config_count": payload["config_count"],
        "configs": payload["configs"],
        "summary": payload["summary"],
    }
    return _write_json_artifact(artifact_path, artifact)


def run_memory_ablation_v2(artifact_path=DEFAULT_MEMORY_ABLATION_V2_PATH, repetitions=5):
    payload = run_large_scale_memory_experiment(repetitions=repetitions)
    artifact = {
        "schema_version": METRICS_SCHEMA_VERSION,
        "artifact_type": "memory-ablation-v2",
        "captured_at": _utc_timestamp(),
        "task_count": payload["task_count"],
        "runs_per_variant": payload["runs_per_variant"],
        "category_counts": payload["category_counts"],
        "variants": payload["variants"],
        "rows": payload["rows"],
    }
    return _write_json_artifact(artifact_path, artifact)


def run_recovery_ablation_v2(artifact_path=DEFAULT_RECOVERY_ABLATION_V2_PATH, repetitions=3):
    repetitions = int(repetitions)
    variants = {"resume_enabled": [], "resume_disabled": []}
    for task in RECOVERY_ABLATION_TASKS:
        for _ in range(repetitions):
            for variant in variants:
                variants[variant].append(_run_recovery_task_variant(task, variant))
    artifact = {
        "schema_version": METRICS_SCHEMA_VERSION,
        "artifact_type": "recovery-ablation-v2",
        "captured_at": _utc_timestamp(),
        "task_count": len(RECOVERY_ABLATION_TASKS),
        "variants": {
            variant: {
                "summary": _recovery_variant_summary(rows),
                "rows": rows,
            }
            for variant, rows in variants.items()
        },
    }
    return _write_json_artifact(artifact_path, artifact)
