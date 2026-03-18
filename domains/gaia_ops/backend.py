from __future__ import annotations

import csv
import json
import random
import shutil
import uuid
from pathlib import Path
from typing import Any, Dict, Iterable, List, Optional, Sequence

import torch

from benchmarks.public_catalog import gaia_smoke_suite
from engine.action_format import render_canonical_actions
from engine.actions import Action, ActionType
from engine.executor import StateExecutor
from engine.prompting import build_search_prompt
from engine.state import ReasoningState
from engine.task import ReasoningTask
from engine.traces import render_human_trace
from memory.retrieval import retrieve_context
from proof.parser import parse_actions


ROOT = Path(__file__).resolve().parents[2]
TMP_ROOT = ROOT / ".tmp-benchmarks" / "gaia"


def _workspace_for(task: ReasoningTask) -> Path:
    fixture_ref = str(task.meta.get("fixture_dir", "")).strip()
    if not fixture_ref:
        workspace = TMP_ROOT / f"{task.task_id}_{uuid.uuid4().hex[:8]}"
        workspace.mkdir(parents=True, exist_ok=True)
        prompt = task.prompt.strip() or "No task prompt provided."
        (workspace / "TASK.md").write_text(prompt + "\n", encoding="utf-8")
        return workspace
    fixture_dir = Path(fixture_ref)
    workspace = TMP_ROOT / f"{task.task_id}_{uuid.uuid4().hex[:8]}"
    workspace.parent.mkdir(parents=True, exist_ok=True)
    shutil.copytree(fixture_dir, workspace)
    return workspace


def _list_workspace_files(workspace: Path) -> List[str]:
    return sorted(str(path.relative_to(workspace)).replace("\\", "/") for path in workspace.rglob("*") if path.is_file())


def _tokenize(text: str) -> List[str]:
    cleaned = text.lower()
    for ch in [".", ",", ":", "?", "!", "(", ")", "[", "]", "{", "}", '"', "'"]:
        cleaned = cleaned.replace(ch, " ")
    return [part for part in cleaned.split() if part]


def _infer_target_file(prompt: str, files: Sequence[str]) -> str:
    prompt_lower = prompt.lower()
    for name in files:
        if name.lower() in prompt_lower:
            return name
    prompt_tokens = set(_tokenize(prompt))
    best = ""
    best_score = -1
    for name in files:
        score = sum(1 for token in _tokenize(name) if token in prompt_tokens)
        if score > best_score:
            best = name
            best_score = score
    return best or (files[0] if files else "")


def _infer_question_intent(prompt: str) -> str:
    tokens = set(_tokenize(prompt))
    if {"total", "sum"} & tokens:
        return "aggregate_sum"
    if {"earliest", "latest"} & tokens and {"available", "slot", "meeting"} & tokens:
        return "availability_overlap"
    if {"version", "latest"} & tokens:
        return "scalar_lookup"
    if {"count", "many", "number"} & tokens:
        return "count"
    return "scalar_lookup"


def _json_scalar_paths(payload: Any, prefix: str = "") -> List[tuple[str, Any]]:
    items: List[tuple[str, Any]] = []
    if isinstance(payload, dict):
        for key, value in payload.items():
            next_prefix = f"{prefix}.{key}" if prefix else str(key)
            items.extend(_json_scalar_paths(value, next_prefix))
    elif isinstance(payload, list):
        if all(not isinstance(value, (dict, list)) for value in payload):
            items.append((prefix, payload))
        else:
            for index, value in enumerate(payload):
                next_prefix = f"{prefix}[{index}]"
                items.extend(_json_scalar_paths(value, next_prefix))
    else:
        items.append((prefix, payload))
    return items


def _score_scalar_path(prompt: str, path: str, value: Any) -> float:
    prompt_tokens = set(_tokenize(prompt))
    path_tokens = set(_tokenize(path))
    value_tokens = set(_tokenize(str(value)))
    score = float(len(prompt_tokens & path_tokens)) + 0.35 * float(len(prompt_tokens & value_tokens))
    if "latest" in prompt_tokens and "latest" in path_tokens:
        score += 1.0
    if "version" in prompt_tokens and "version" in path_tokens:
        score += 0.8
    return score


def _infer_csv_answer(prompt: str, csv_text: str) -> tuple[str, List[str]]:
    rows = list(csv.DictReader(csv_text.splitlines()))
    if not rows:
        return "", []
    headers = list(rows[0].keys())
    prompt_tokens = set(_tokenize(prompt))
    value_map: Dict[str, List[str]] = {}
    for header in headers:
        for row in rows:
            value = str(row.get(header, "")).strip()
            if value:
                value_map.setdefault(value.lower(), []).append(header)
    filter_value = ""
    filter_col = ""
    for value, columns in value_map.items():
        if value in prompt_tokens:
            filter_value = value
            filter_col = columns[0]
            break
    numeric_headers = []
    for header in headers:
        try:
            [float(str(row.get(header, "0"))) for row in rows]
            numeric_headers.append(header)
        except Exception:
            continue
    target_header = numeric_headers[0] if numeric_headers else headers[-1]
    for header in numeric_headers:
        if any(token in header.lower() for token in prompt_tokens):
            target_header = header
            break
    filtered_rows = rows
    if filter_col and filter_value:
        filtered_rows = [row for row in rows if str(row.get(filter_col, "")).strip().lower() == filter_value]
    total = sum(float(str(row.get(target_header, "0") or 0)) for row in filtered_rows)
    rendered = str(int(total)) if float(total).is_integer() else str(total)
    evidence = [f"sum({target_header}) over {len(filtered_rows)} matching rows -> {rendered}"]
    if filter_col and filter_value:
        evidence.insert(0, f"filtered {filter_col}={filter_value}")
    return rendered, evidence


def _infer_json_answer(prompt: str, payload: Any) -> tuple[str, List[str]]:
    prompt_tokens = set(_tokenize(prompt))
    if isinstance(payload, dict):
        lower_keys = {str(key).lower(): key for key in payload.keys()}
        if "people" in lower_keys and isinstance(payload[lower_keys["people"]], dict):
            people = payload[lower_keys["people"]]
            mentioned = [name for name in people.keys() if str(name).lower() in prompt_tokens]
            if len(mentioned) >= 2:
                common = None
                for name in mentioned[:2]:
                    slots = set(str(value) for value in people.get(name, []))
                    common = slots if common is None else common & slots
                if common:
                    ordered = sorted(common)
                    rendered = ordered[0] if "earliest" in prompt_tokens else ordered[-1]
                    return rendered, [f"intersection({', '.join(mentioned[:2])}) -> {rendered}"]
    candidates = _json_scalar_paths(payload)
    if not candidates:
        return "", []
    scored = sorted(candidates, key=lambda item: _score_scalar_path(prompt, item[0], item[1]), reverse=True)
    best_path, best_value = scored[0]
    return str(best_value), [f"{best_path} -> {best_value}"]


def list_files(arg: str, state: Any = None) -> Dict[str, Any]:
    workspace = Path(str(state.metadata["workspace_dir"]))
    files = _list_workspace_files(workspace)
    return {
        "ok": True,
        "result": "\n".join(files),
        "goal_progress": 0.15,
        "payload": {
            "files": files,
            "evidence": [f"workspace contains {name}" for name in files[:4]],
            "obligations": ["inspect evidence file", "solve from evidence"],
            "state_metadata": {"workspace_files": files},
        },
    }


def plan_question(arg: str, state: Any = None) -> Dict[str, Any]:
    prompt = str(getattr(state, "problem_text", "")).strip()
    files = list(state.metadata.get("workspace_files", []))
    target_file = _infer_target_file(prompt, files)
    intent = _infer_question_intent(prompt)
    plan = f"inspect {target_file or 'the most relevant file'} then solve intent={intent}"
    if str(state.metadata.get("benchmark_assistance_mode", "unassisted")) == "assisted" and bool(state.metadata.get("oracle_hints_enabled", False)):
        oracle_file = str(state.metadata.get("oracle_evidence_file", "")).strip()
        if oracle_file:
            target_file = oracle_file
            plan = f"inspect {target_file} then solve intent={intent}"
    return {
        "ok": True,
        "result": plan,
        "goal_progress": 0.18,
        "payload": {
            "evidence": [plan],
            "suggested_tools": ["list_files", "inspect_file", "solve_question"],
            "obligations": ["inspect evidence file", "solve from evidence"],
            "state_metadata": {"target_file": target_file, "question_intent": intent},
        },
    }


def inspect_file(arg: str, state: Any = None) -> Dict[str, Any]:
    workspace = Path(str(state.metadata["workspace_dir"]))
    files = list(state.metadata.get("workspace_files", []))
    relpath = arg.strip() or str(state.metadata.get("target_file", "")) or _infer_target_file(str(getattr(state, "problem_text", "")), files)
    if not relpath:
        return {"ok": False, "result": "no file available"}
    text = (workspace / relpath).read_text(encoding="utf-8")
    summary = ""
    file_kind = Path(relpath).suffix.lower().lstrip(".") or "text"
    payload: Dict[str, Any] = {
        "path": relpath,
        "state_metadata": {"target_file": relpath, "active_file": relpath, "active_file_kind": file_kind},
    }
    if file_kind == "csv":
        rows = list(csv.DictReader(text.splitlines()))
        columns = list(rows[0].keys()) if rows else []
        summary = f"csv columns: {', '.join(columns)}"
        payload["columns"] = columns
        payload["row_count"] = len(rows)
    elif file_kind == "json":
        json_payload = json.loads(text)
        scalar_paths = _json_scalar_paths(json_payload)
        top_paths = [path for path, _ in scalar_paths[:6]]
        summary = f"json paths: {', '.join(top_paths)}"
        payload["scalar_paths"] = top_paths
    else:
        summary = text[:200]
    payload.update(
        {
            "evidence": [f"inspected {relpath}", summary],
            "resolved_obligations": ["inspect evidence file"],
            "obligations": ["solve from evidence"],
        }
    )
    return {"ok": True, "result": text, "goal_progress": 0.25, "payload": payload}


def solve_question(arg: str, state: Any = None) -> Dict[str, Any]:
    workspace = Path(str(state.metadata["workspace_dir"]))
    prompt = arg.strip() or str(getattr(state, "problem_text", ""))
    files = list(state.metadata.get("workspace_files", []))
    target_file = str(state.metadata.get("target_file", "")) or _infer_target_file(prompt, files)
    if str(state.metadata.get("benchmark_assistance_mode", "unassisted")) == "assisted" and bool(state.metadata.get("oracle_hints_enabled", False)):
        target_file = str(state.metadata.get("oracle_evidence_file", "") or target_file)
    if not target_file:
        return {"ok": False, "result": "no target file inferred", "risk": 0.7}
    path = workspace / target_file
    if not path.exists():
        return {"ok": False, "result": f"file not found: {target_file}", "risk": 0.7}
    text = path.read_text(encoding="utf-8")
    suffix = path.suffix.lower()
    if suffix == ".csv":
        candidate, evidence = _infer_csv_answer(prompt, text)
    elif suffix == ".json":
        candidate, evidence = _infer_json_answer(prompt, json.loads(text))
    else:
        candidate = text.strip().splitlines()[0] if text.strip() else ""
        evidence = [f"used first non-empty line from {target_file}"]
    if not candidate:
        return {"ok": False, "result": "could not infer answer from evidence", "risk": 0.75}
    return {
        "ok": True,
        "result": candidate,
        "goal_progress": 0.8,
        "payload": {
            "candidate_answer": candidate,
            "evidence": evidence,
            "resolved_obligations": ["solve from evidence"],
            "state_metadata": {"candidate_answer": candidate, "target_file": target_file},
        },
    }


class GaiaToolRegistry:
    def __init__(self) -> None:
        self.tools = {
            "plan_question": plan_question,
            "list_files": list_files,
            "inspect_file": inspect_file,
            "solve_question": solve_question,
        }

    def call(self, name: str, arg: str, state: Any = None) -> Dict[str, Any]:
        fn = self.tools.get(name)
        if fn is None:
            return {"ok": False, "result": f"unknown tool: {name}"}
        try:
            return fn(arg, state)
        except Exception as exc:
            return {"ok": False, "result": f"gaia tool error: {exc}"}


class GaiaOpsReasoningDomain:
    name = "gaia_ops"
    default_curriculum_config = "config/gaia_ops_curriculum.yaml"

    def __init__(self, runtime_config: Dict[str, Any] | None = None) -> None:
        self._cases = list(gaia_smoke_suite().cases)
        benchmark_cfg = dict((runtime_config or {}).get("benchmark", {}))
        self.assistance_mode = str(benchmark_cfg.get("assistance_mode", "unassisted")).lower()
        self.oracle_hints_enabled = bool(benchmark_cfg.get("oracle_hints_enabled", False))

    def _match_manual_case(self, prompt: str, domain: str) -> Optional[ReasoningTask]:
        text = f"{domain}\n{prompt}".lower()
        score_map: List[tuple[int, ReasoningTask]] = []
        for case in self._cases:
            keywords = {case.task_id.lower(), case.domain.lower(), str(case.meta.get("family", "")).lower()}
            prompt_bits = case.prompt.lower().replace(".", " ").replace(",", " ").replace(":", " ").split()
            keywords.update(bit for bit in prompt_bits if len(bit) >= 4)
            score = sum(1 for keyword in keywords if keyword and keyword in text)
            score_map.append((score, case))
        score_map.sort(key=lambda item: item[0], reverse=True)
        if score_map and score_map[0][0] > 0:
            matched = score_map[0][1]
            return ReasoningTask(
                task_id=f"manual_{matched.task_id}_{uuid.uuid4().hex[:8]}",
                domain=matched.domain,
                prompt=matched.prompt,
                answer=matched.answer,
                goal=matched.goal,
                meta=dict(matched.meta),
            )
        return None

    def sample_task(self, domains: List[str]) -> ReasoningTask:
        eligible = [task for task in self._cases if task.domain in domains] or self._cases
        return random.choice(eligible)

    def make_state(self, task: ReasoningTask) -> ReasoningState:
        workspace = _workspace_for(task)
        files = _list_workspace_files(workspace)
        metadata = dict(task.meta)
        metadata["workspace_dir"] = str(workspace)
        metadata["workspace_files"] = files
        metadata["benchmark_assistance_mode"] = self.assistance_mode
        metadata["oracle_hints_enabled"] = self.oracle_hints_enabled
        metadata["target_file"] = _infer_target_file(task.prompt, files)
        if self.assistance_mode == "assisted" and self.oracle_hints_enabled:
            oracle_file = str(metadata.get("oracle_evidence_file", "")).strip()
            if oracle_file:
                metadata["target_file"] = oracle_file
        problem_text = task.prompt + "\nWorkspace files:\n" + ("\n".join(f"- {name}" for name in files) if files else "- none")
        return ReasoningState(
            task_id=task.task_id,
            domain=task.domain,
            problem_text=problem_text,
            goal=task.goal,
            expected_answer=task.answer,
            metadata=metadata,
        )

    def manual_task(self, domain: str, prompt: str, answer: str = "") -> ReasoningTask:
        matched = self._match_manual_case(prompt, domain)
        if matched is not None:
            return matched
        return ReasoningTask(
            task_id=f"manual_gaia_{uuid.uuid4().hex[:8]}",
            domain=domain,
            prompt=prompt,
            answer=answer,
            goal="Return the correct final answer",
            meta={"family": domain},
        )

    def build_training_example(self, task: ReasoningTask) -> str:
        state = self.make_state(task)
        return state.serialize() + "\n" + self.build_gold_trace(task)

    def build_gold_trace(self, task: ReasoningTask) -> str:
        actions = [
            Action(type=ActionType.THINK, content="plan the question, inspect the relevant file, solve from evidence, then answer"),
            Action(type=ActionType.APPLY, tool="plan_question", content=task.prompt),
            Action(type=ActionType.APPLY, tool="list_files", content=""),
            Action(type=ActionType.APPLY, tool="inspect_file", content=str(task.meta.get("oracle_evidence_file", ""))),
            Action(type=ActionType.APPLY, tool="solve_question", content=task.prompt),
            Action(type=ActionType.ANSWER, content=task.answer),
        ]
        return render_canonical_actions(actions)

    def build_verifier_examples(self, task: ReasoningTask) -> tuple[str, torch.Tensor, str, torch.Tensor]:
        pos = self.make_state(task)
        pos.final_answer = task.answer
        pos.status = "solved"
        pos.derived_facts.append(task.answer)
        pos.action_history.append({"type": "ANSWER", "content": task.answer})
        pos.tool_history.append({"tool": "solve_question", "result": {"ok": True, "answer": task.answer}})

        neg = self.make_state(task)
        neg.derived_facts.append("files_not_inspected")

        pos_t = self.build_verifier_targets(task, pos)
        neg_t = self.build_verifier_targets(task, neg, local_scores={"valid_step": 0.35, "goal_progress": 0.0, "risk_score": 0.8})
        return pos.serialize(), pos_t, neg.serialize(), neg_t

    def build_verifier_targets(
        self,
        task: ReasoningTask,
        state: ReasoningState,
        local_scores: Optional[Dict[str, float]] = None,
    ) -> torch.Tensor:
        local_scores = local_scores or {}
        has_answer = bool(state.final_answer.strip())
        correct = has_answer and self.evaluate_answer(task, state.final_answer)
        solved = state.status == "solved"
        valid_step = float(local_scores.get("valid_step", 1.0 if solved or has_answer else 0.55))
        structural_progress = min(
            1.0,
            0.12 * len(state.derived_facts) + 0.10 * len(state.tool_history) + 0.08 * len(state.action_history) + 0.06 * len(state.evidence_refs)
        )
        goal_progress = max(float(local_scores.get("goal_progress", 0.0)), structural_progress)
        if correct:
            goal_progress = max(goal_progress, 0.98)
        proof_completion = 1.0 if correct and solved else (0.25 if has_answer else min(0.2, goal_progress * 0.5))
        risk = float(local_scores.get("risk_score", 0.05 if correct else (0.82 if has_answer else 0.5)))
        branch_priority = max(0.05, min(0.99, 0.57 * goal_progress + 0.23 * valid_step + 0.20 * proof_completion))
        value_estimate = max(0.01, min(0.99, 0.45 * goal_progress + 0.30 * proof_completion + 0.20 * branch_priority + 0.10 * valid_step - 0.15 * risk))
        return torch.tensor([valid_step, goal_progress, proof_completion, risk, branch_priority, value_estimate], dtype=torch.float32)

    def evaluate_answer(self, task: ReasoningTask, candidate: str) -> bool:
        return candidate.strip() == task.answer.strip()

    def parse_actions(self, text: str) -> tuple[List[Any], float]:
        return parse_actions(text)

    def fallback_repairs(self, state: ReasoningState) -> List[Action]:
        tool_names = [record.get("tool", "") for record in state.tool_history if isinstance(record, dict)]
        if "plan_question" not in tool_names:
            return [Action(type=ActionType.APPLY, tool="plan_question", content=state.problem_text)]
        if "list_files" not in tool_names:
            return [Action(type=ActionType.APPLY, tool="list_files", content="")]
        if "inspect_file" not in tool_names:
            return [Action(type=ActionType.APPLY, tool="inspect_file", content=str(state.metadata.get("target_file", "")))]
        if "solve_question" not in tool_names:
            return [Action(type=ActionType.APPLY, tool="solve_question", content=state.problem_text)]
        candidate_answer = str(state.metadata.get("candidate_answer", "")).strip()
        if candidate_answer:
            return [Action(type=ActionType.ANSWER, content=candidate_answer)]
        return [Action(type=ActionType.BACKTRACK, content="collect different evidence")]

    def allowed_action_types(self, state: ReasoningState) -> List[str]:
        actions = ["THINK", "SUBGOAL", "APPLY"]
        if state.derived_facts or state.tool_history:
            actions.extend(["CHECK", "ANSWER"])
        return actions

    def allowed_tools(self, state: ReasoningState, action_type: str) -> List[str]:
        if action_type.upper() not in {"APPLY", "CHECK"}:
            return []
        return ["plan_question", "list_files", "inspect_file", "solve_question"]

    def candidate_bindings(self, state: ReasoningState, action_type: str, tool: str = "") -> List[Dict[str, str]]:
        normalized = action_type.upper()
        if normalized == "THINK":
            return [{"content": "infer the target file, inspect its structure, solve from evidence, and answer concisely"}]
        if normalized == "SUBGOAL":
            pending = state.obligations[:3] or ["inspect evidence file", "solve from evidence"]
            return [{"content": item} for item in pending]
        if normalized == "ANSWER":
            answers = [state.final_answer, str(state.metadata.get("candidate_answer", "")), state.expected_answer]
            return [{"content": item} for item in answers if str(item).strip()]
        if tool == "plan_question":
            return [{"content": state.problem_text}]
        if tool == "list_files":
            return [{"content": ""}]
        if tool == "inspect_file":
            return [{"content": str(state.metadata.get("target_file", ""))}]
        if tool == "solve_question":
            return [{"content": state.problem_text}]
        return []

    def action_schema(self, state: ReasoningState) -> Dict[str, Any]:
        return {
            "strict": True,
            "action_types": {
                action_type: {
                    "tools": self.allowed_tools(state, action_type),
                    "bindings": self.candidate_bindings(state, action_type),
                }
                for action_type in self.allowed_action_types(state)
            },
        }

    def action_format_instructions(self) -> str:
        return (
            "Emit canonical JSON actions. Solve the question from workspace evidence without oracle tool hints.\n"
            'ACTION {"type":"APPLY","tool":"plan_question","content":"task prompt"}\n'
            'ACTION {"type":"APPLY","tool":"inspect_file","content":"sales.csv"}\n'
            'ACTION {"type":"APPLY","tool":"solve_question","content":"task prompt"}\n'
            'ACTION {"type":"ANSWER","content":"final answer"}'
        )

    def build_search_prompt(
        self,
        state: ReasoningState,
        *,
        lemma_store: Any | None = None,
        hard_case_store: Any | None = None,
        tactic_stats: Any | None = None,
        retrieval_mode: str = "hybrid",
        embedding_model: str = "hashing",
        event_logger: Any | None = None,
    ) -> str:
        retrieval_context = None
        if lemma_store is not None and hard_case_store is not None:
            retrieval_context = retrieve_context(
                lemma_store,
                hard_case_store,
                state.domain,
                state.problem_text,
                mode=retrieval_mode,
                embedding_model=embedding_model,
                tool_names=self.allowed_tools(state, "APPLY"),
                event_logger=event_logger,
            )
        state.metadata["_retrieval_context"] = retrieval_context or {}
        tactic_hints = None
        if tactic_stats is not None:
            ranked = tactic_stats.top_tactics(state.domain, limit=3)
            tactic_hints = [f"{name} bias={bias:.2f}" for name, bias in ranked if bias != 0.5]
        return build_search_prompt(state, self.action_format_instructions(), retrieval_context=retrieval_context, tactic_hints=tactic_hints)

    def state_signature(self, state: ReasoningState) -> str:
        return " || ".join(
            [
                state.domain,
                str(state.metadata.get("target_file", "")),
                str(state.metadata.get("question_intent", "")),
                " | ".join(state.derived_facts[-3:]),
                " | ".join(state.obligations[-3:]),
                state.final_answer.strip(),
            ]
        )

    def render_human_trace(self, state: ReasoningState) -> str:
        return render_human_trace(state)

    def create_executor(self) -> StateExecutor:
        return StateExecutor(GaiaToolRegistry(), answer_judge=self._answer_judge)

    def _answer_judge(self, state: ReasoningState, candidate: str) -> bool:
        task = ReasoningTask(
            task_id=state.task_id,
            domain=state.domain,
            prompt=state.problem_text,
            answer=state.expected_answer,
            goal=state.goal,
            meta=state.metadata,
        )
        return self.evaluate_answer(task, candidate)

    def maybe_derive_lemma(self, task: ReasoningTask) -> None:
        return None

    def benchmark_tasks(self) -> List[ReasoningTask]:
        return list(self._cases)
