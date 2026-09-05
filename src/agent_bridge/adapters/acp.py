from __future__ import annotations

import asyncio
import contextlib
import json
import logging
import subprocess
import sys
from collections.abc import Iterable
from pathlib import Path
from typing import Any, NoReturn

from acp import PROTOCOL_VERSION, connect_to_agent, text_block
from acp.schema import (
    AllowedOutcome,
    ClientCapabilities,
    DeniedOutcome,
    Implementation,
    PermissionOption,
    RequestPermissionResponse,
)

from agent_bridge.acp_config import config_option_values
from agent_bridge.adapters.base import STDIO_LIMIT, Adapter
from agent_bridge.claude_meta import (
    CLAUDE_MODE_BYPASS,
    apply_claude_gateway_env,
    resolve_claude_effort,
)
from agent_bridge.config import AgentConfig
from agent_bridge.devin_meta import DEVIN_MODE_BYPASS, apply_devin_env
from agent_bridge.dsh_home import prepare_dsh_launch, resolve_dsh_command
from agent_bridge.kimi_meta import KIMI_MODE_YOLO, resolve_kimi_thinking
from agent_bridge.models import Session, Task, TurnResult, dsh_effort, grok_effort
from agent_bridge.opencode_meta import resolve_opencode_effort
from agent_bridge.processes import (
    drop_pid,
    process_create_time,
    process_image_name,
    reap_subprocess,
    record_pid,
    resolve_command,
)
from agent_bridge.transcript import append_event
from agent_bridge.worker_env import build_worker_env
from agent_bridge.workspace import collect_update_paths

STDERR_TAIL_LIMIT = 16000

log = logging.getLogger(__name__)

GROK_SET_MODEL_METHODS = ("session/setModel", "session/set_model")
# These workers' session/load replays persisted history as session/update
# notifications. session/resume is advertised and skips that replay.
_RESUME_AGENTS = frozenset({"kimi", "opencode", "claude"})
_CONFIG_OPTION_AGENTS = frozenset({"kimi", "opencode", "claude", "devin"})
_MODEL_EFFORT_AGENTS = frozenset({"grok", "dsh", "kimi", "opencode", "claude", "devin", "cursor"})

# Handshake-style RPCs (initialize, session/new, session/load, setModel)
# normally answer in seconds. A worker that wedges before the prompt would
# otherwise hang dispatch forever; prompt itself stays unbounded by design.
RPC_TIMEOUT_SEC = 60.0
CURSOR_MODEL_LIST_TIMEOUT_SEC = 30.0

# ACP ToolKind values that can change the workspace. Read-only kinds (read,
# search, fetch, think, ...) also carry locations; counting them would report
# files the agent merely opened. Under-matching is safe: the disk snapshot
# diff in merge_files_changed still catches every real write.
MUTATING_TOOL_KINDS = {"edit", "delete", "move", "write", "create"}
_TOOL_IO_LIMIT = 500


def _tool_io_summary(value: Any) -> str | None:
    if value is None:
        return None
    text = value if isinstance(value, str) else json.dumps(value, ensure_ascii=False, default=str)
    return text if len(text) <= _TOOL_IO_LIMIT else text[:_TOOL_IO_LIMIT] + "…"


class RpcTimeoutError(RuntimeError):
    pass


def grok_session_meta(
    base: dict[str, Any] | None,
    model: str | None = None,
    effort: str | None = None,
) -> dict[str, Any]:
    """Hints for Grok ``session/new`` ``_meta`` (yolo + optional model/effort).

    Official pager/tests inject ``modelId`` and ``reasoningEffort`` there.
    ``yoloMode`` must stay explicit (absent is not false). Those hints are not
    sticky: Grok ``/new`` still lands on the campaign default (currently
    grok-4.6 xhigh). Bridge must ``session/setModel`` after the session exists.
    """
    meta = dict(base or {})
    if model:
        meta["modelId"] = model
    mapped = grok_effort(effort)
    if mapped:
        meta["reasoningEffort"] = mapped
    return meta


def with_grok_cli_selection(
    command: list[str],
    model: str | None,
    effort: str | None,
) -> list[str]:
    """Stamp Grok ``agent --model/--effort`` before ``stdio``.

    Process flags only seed the spawn default. Grok ``/new`` still resets to
    the campaign model; a later ``session/setModel`` is what sticks.
    """
    extras: list[str] = []
    if model:
        extras += ["--model", model]
    mapped = grok_effort(effort)
    if mapped:
        extras += ["--effort", mapped]
    if not extras:
        return list(command)
    cmd = list(command)
    for token in ("stdio", "headless", "serve"):
        if token in cmd:
            index = cmd.index(token)
            return cmd[:index] + extras + cmd[index:]
    return cmd + extras


def with_cursor_cli_model(command: list[str], model: str | None) -> list[str]:
    """Pin Cursor's model before its ACP subcommand."""
    cmd = list(command)
    if not model:
        return cmd
    try:
        index = cmd.index("acp")
    except ValueError:
        raise RuntimeError(
            "cursor model selection requires an 'acp' token in the configured command"
        ) from None
    return [*cmd[:index], "--model", model, *cmd[index:]]


def cursor_list_models_command(command: list[str]) -> list[str]:
    """Build the matching Cursor CLI model-discovery command."""
    cmd = list(command)
    try:
        index = cmd.index("acp")
    except ValueError:
        raise RuntimeError(
            "cursor model discovery requires an 'acp' token in the configured command"
        ) from None
    executable = Path(cmd[0]).name.lower()
    if executable in {"agent", "agent.exe"}:
        return [*cmd[:index], "models"]
    return [*cmd[:index], "--list-models"]


def parse_cursor_models(output: str) -> list[str]:
    """Parse the stable ``<id> - <label>`` rows from ``--list-models``."""
    models: list[str] = []
    for raw_line in output.splitlines():
        model, separator, _label = raw_line.strip().partition(" - ")
        if separator and model and not any(char.isspace() for char in model):
            models.append(model)
    return models


def dsh_needs_respawn(
    applied_model: str | None,
    applied_effort: str | None,
    model: str | None,
    effort: str | None,
) -> bool:
    return applied_model != model or applied_effort != dsh_effort(effort)


def _dump(obj: Any) -> Any:
    if obj is None:
        return None
    if hasattr(obj, "model_dump"):
        return obj.model_dump(mode="json", by_alias=True, exclude_none=True)
    if isinstance(obj, (dict, list, str, int, float, bool)):
        return obj
    return str(obj)


def _collect_paths(obj: Any, into: set[str]) -> None:
    collect_update_paths(obj, into)


def _has_diff_content(dumped: dict[str, Any]) -> bool:
    content = dumped.get("content")
    if not isinstance(content, list):
        return False
    return any(isinstance(item, dict) and item.get("type") == "diff" for item in content)


def should_collect_tool_paths(
    type_name: str,
    dumped: Any,
    known_kinds: dict[str, str],
) -> bool:
    """Decide whether a session update may contribute to files_changed.

    Only tool calls with a mutating ``kind`` (or an explicit diff content)
    count. ``known_kinds`` maps toolCallId -> kind so that progress updates,
    which often omit ``kind``, inherit it from their start event.
    """
    if not isinstance(dumped, dict):
        return False
    if type_name not in {"ToolCallStart", "ToolCallProgress", "ToolCallUpdate"}:
        return False
    call_id = str(dumped.get("toolCallId") or "")
    kind = str(dumped.get("kind") or "").lower()
    if type_name == "ToolCallStart" and call_id:
        known_kinds[call_id] = kind
    if not kind and call_id:
        kind = known_kinds.get(call_id, "")
    return kind in MUTATING_TOOL_KINDS or _has_diff_content(dumped)


def _text_of(content: Any) -> str:
    if content is None:
        return ""
    if isinstance(content, str):
        return content
    if hasattr(content, "text") and isinstance(content.text, str):
        return content.text
    dumped = _dump(content)
    if isinstance(dumped, dict):
        if isinstance(dumped.get("text"), str):
            return dumped["text"]
        return json.dumps(dumped, ensure_ascii=False)
    if isinstance(dumped, list):
        return "".join(_text_of(item) for item in dumped)
    return str(dumped)


def _pick_permission_option(options: Iterable[PermissionOption]) -> PermissionOption | None:
    ranked: list[tuple[int, PermissionOption]] = []
    for option in options:
        kind = str(getattr(option, "kind", "")).lower().replace("_", "-")
        option_id = str(getattr(option, "option_id", "")).lower().replace("_", "-")
        blob = f"{kind} {option_id}"
        if "allow-always" in blob or kind == "allow-always":
            score = 0
        elif "allow-once" in blob or kind == "allow-once" or blob.strip().startswith("allow"):
            score = 1
        else:
            score = 50
        ranked.append((score, option))
    ranked.sort(key=lambda item: item[0])
    return ranked[0][1] if ranked else None


class _BridgeClient:
    def __init__(self, session_id: str, home: Path) -> None:
        self.session_id = session_id
        self.home = home
        self.text_parts: list[str] = []
        self.files: set[str] = set()
        self.usage: dict[str, Any] = {}
        self.tool_kinds: dict[str, str] = {}

    def reset_turn(self) -> None:
        self.text_parts = []
        self.files = set()
        self.usage = {}
        self.tool_kinds = {}

    async def request_permission(
        self,
        session_id: str,
        tool_call: Any,
        options: list[Any] | None,
        **kwargs: Any,
    ) -> RequestPermissionResponse:
        option = _pick_permission_option(options or [])
        dumped = _dump(tool_call)
        if option is None:
            append_event(
                self.session_id,
                "permission",
                {"decision": "cancelled", "tool_call": dumped},
                self.home,
            )
            return RequestPermissionResponse(outcome=DeniedOutcome(outcome="cancelled"))
        append_event(
            self.session_id,
            "permission",
            {"decision": "selected", "option_id": option.option_id, "tool_call": dumped},
            self.home,
        )
        return RequestPermissionResponse(
            outcome=AllowedOutcome(option_id=option.option_id, outcome="selected")
        )

    async def session_update(self, session_id: str, update: Any, **kwargs: Any) -> None:
        dumped = _dump(update)
        type_name = type(update).__name__
        text = ""
        event_type = "raw"
        if type_name == "AgentMessageChunk":
            event_type = "message_chunk"
            text = _text_of(getattr(update, "content", dumped))
            if text:
                self.text_parts.append(text)
        elif type_name == "AgentThoughtChunk":
            event_type = "thought_chunk"
            text = _text_of(getattr(update, "content", dumped))
        elif type_name == "UserMessageChunk":
            event_type = "raw"
        elif type_name == "ToolCallStart":
            event_type = "tool_call"
        elif type_name in {"ToolCallProgress", "ToolCallUpdate"}:
            event_type = "tool_call_update"
        elif type_name in {"AgentPlanUpdate", "AgentPlanContentUpdate"}:
            event_type = "plan"
        elif type_name == "UsageUpdate":
            event_type = "raw"
            self.usage = dumped if isinstance(dumped, dict) else {"raw": dumped}
        if should_collect_tool_paths(type_name, dumped, self.tool_kinds):
            _collect_paths(dumped, self.files)
        data: dict[str, Any] = {"update_type": type_name}
        if text:
            data["text"] = text
        if isinstance(dumped, dict):
            title = dumped.get("title")
            if title:
                data["title"] = title
            if dumped.get("path"):
                data["path"] = dumped["path"]
        if event_type in {"tool_call", "tool_call_update"} and isinstance(dumped, dict):
            for src, dst in (("toolCallId", "tool_call_id"), ("kind", "kind"), ("status", "status")):
                if dumped.get(src) is not None:
                    data[dst] = dumped[src]
            locations = dumped.get("locations")
            if isinstance(locations, list):
                paths = [loc.get("path") for loc in locations if isinstance(loc, dict) and loc.get("path")]
                if paths:
                    data["locations"] = paths[:20]
            if event_type == "tool_call":
                summary = _tool_io_summary(dumped.get("rawInput"))
                if summary is not None:
                    data["input"] = summary
            elif dumped.get("status") == "failed":
                summary = _tool_io_summary(dumped.get("rawOutput"))
                if summary is not None:
                    data["output"] = summary
        append_event(self.session_id, event_type, data, self.home)

    async def write_text_file(self, session_id: str, path: str, content: str, **kwargs: Any) -> NoReturn:
        raise RuntimeError("filesystem client methods are disabled")

    async def read_text_file(
        self,
        session_id: str,
        path: str,
        line: int | None = None,
        limit: int | None = None,
        **kwargs: Any,
    ) -> NoReturn:
        raise RuntimeError("filesystem client methods are disabled")

    async def create_terminal(
        self,
        session_id: str,
        command: str,
        args: list[str] | None = None,
        env: list[Any] | None = None,
        cwd: str | None = None,
        output_byte_limit: int | None = None,
        **kwargs: Any,
    ) -> NoReturn:
        raise RuntimeError("terminal client methods are disabled")

    async def terminal_output(self, session_id: str, terminal_id: str, **kwargs: Any) -> NoReturn:
        raise RuntimeError("terminal client methods are disabled")

    async def release_terminal(self, session_id: str, terminal_id: str, **kwargs: Any) -> None:
        return None

    async def wait_for_terminal_exit(self, session_id: str, terminal_id: str, **kwargs: Any) -> NoReturn:
        raise RuntimeError("terminal client methods are disabled")

    async def kill_terminal(self, session_id: str, terminal_id: str, **kwargs: Any) -> None:
        return None

    async def create_elicitation(self, message: str, mode: Any, **kwargs: Any) -> Any:
        from acp.schema import DeclineElicitationResponse

        return DeclineElicitationResponse(action="decline")

    async def complete_elicitation(self, elicitation_id: str, **kwargs: Any) -> None:
        return None

    async def ext_method(self, method: str, params: Any) -> dict[str, Any]:
        return {}

    async def ext_notification(self, method: str, params: Any) -> None:
        return None

    def on_connect(self, conn: Any) -> None:
        return None


class _Live:
    def __init__(self) -> None:
        self.proc: asyncio.subprocess.Process | None = None
        self.conn: Any = None
        self.client: _BridgeClient | None = None
        self.stderr_task: asyncio.Task[None] | None = None
        self.stderr_tail = ""
        self.prompt_task: asyncio.Task[Any] | None = None
        self.applied_model: str | None = None
        self.applied_effort: str | None = None
        self.applied_mode: str | None = None
        # Latest `configOptions` snapshot from a Kimi lifecycle or
        # set_config_option response: the only place the model's advertised
        # thinking levels are published.
        self.config_options: list[Any] = []
        # Warnings raised outside a turn (e.g. during ensure_session);
        # drained into the next TurnResult.
        self.pending_warnings: list[str] = []


class AcpAdapter(Adapter):
    def __init__(self, agent: AgentConfig, home: Path, env_config=None) -> None:
        super().__init__(agent, home, env_config)
        self._live: dict[str, _Live] = {}

    def _env(self) -> dict[str, str]:
        env = build_worker_env(self.agent.env, config=self.env_config, worker_context=True)
        if self.agent.name == "claude":
            return apply_claude_gateway_env(env)
        if self.agent.name == "devin":
            return apply_devin_env(env)
        return env

    async def _drain_stderr(
        self,
        proc: asyncio.subprocess.Process,
        session_id: str,
        live: _Live,
    ) -> None:
        if proc.stderr is None:
            return
        try:
            while True:
                line = await proc.stderr.readline()
                if not line:
                    return
                text = line.decode("utf-8", errors="replace").rstrip()
                if text:
                    live.stderr_tail = f"{live.stderr_tail}\n{text}"[-STDERR_TAIL_LIMIT:]
        except (ValueError, OSError):
            log.warning("stderr drain aborted for %s", session_id, exc_info=True)

    async def _rpc(
        self,
        coro: Any,
        what: str,
        session: Session,
        timeout: float = RPC_TIMEOUT_SEC,
    ) -> Any:
        """Await a handshake RPC with a timeout; kill the worker on hang."""
        try:
            return await asyncio.wait_for(coro, timeout=timeout)
        except TimeoutError:
            live = self._live.get(session.session_id)
            log.error(
                "%s %s timed out after %ss for %s; killing worker stderr_tail=%r",
                self.agent.name,
                what,
                timeout,
                session.session_id,
                live.stderr_tail if live else "",
            )
            await self.shutdown(session)
            raise RpcTimeoutError(
                f"{self.agent.name} {what} timed out after {int(timeout)}s"
            ) from None

    async def _cursor_models(
        self,
        command: list[str],
        env: dict[str, str],
        cwd: str | None,
    ) -> list[str]:
        model_cmd = cursor_list_models_command(command)
        proc = await asyncio.create_subprocess_exec(
            *model_cmd,
            stdout=asyncio.subprocess.PIPE,
            stderr=asyncio.subprocess.PIPE,
            env=env,
            cwd=cwd,
        )
        try:
            stdout, stderr = await asyncio.wait_for(
                proc.communicate(), timeout=CURSOR_MODEL_LIST_TIMEOUT_SEC
            )
        except asyncio.CancelledError:
            await reap_subprocess(proc)
            raise
        except TimeoutError:
            await reap_subprocess(proc)
            raise RuntimeError(
                "cursor model discovery timed out; run 'cursor-agent --list-models' "
                "to check the current account"
            ) from None
        if proc.returncode:
            detail = stderr.decode("utf-8", errors="replace").strip()
            suffix = f": {detail[-1000:]}" if detail else ""
            raise RuntimeError(f"cursor model discovery failed{suffix}")
        models = parse_cursor_models(stdout.decode("utf-8", errors="replace"))
        if not models:
            raise RuntimeError(
                "cursor model discovery returned no model IDs; run "
                "'cursor-agent --list-models' to check the current account"
            )
        return models

    async def _spawn(self, session: Session) -> _Live:
        await self.shutdown(session)
        if self.agent.name == "dsh":
            cmd = resolve_dsh_command(self.agent.command, self.agent.fallback_commands)
        else:
            cmd = resolve_command(self.agent.command, self.agent.fallback_commands)
        env = self._env()
        if self.agent.name == "dsh":
            cmd, env = prepare_dsh_launch(
                cmd,
                env,
                session_id=session.session_id,
                model=session.model,
                effort=session.effort,
            )
        elif self.agent.name == "grok":
            cmd = with_grok_cli_selection(cmd, session.model, session.effort)
        elif self.agent.name == "cursor" and session.model:
            models = await self._cursor_models(
                cmd,
                env,
                self.agent.cwd or session.cwd or None,
            )
            if session.model not in models:
                raise ValueError(
                    f"cursor model {session.model!r} is not available for the current account; "
                    f"available model IDs: {', '.join(models)}"
                )
            cmd = with_cursor_cli_model(cmd, session.model)
        kwargs: dict[str, Any] = {}
        if sys.platform == "win32":
            kwargs["creationflags"] = subprocess.CREATE_NEW_PROCESS_GROUP
        proc = await asyncio.create_subprocess_exec(
            *cmd,
            stdin=asyncio.subprocess.PIPE,
            stdout=asyncio.subprocess.PIPE,
            stderr=asyncio.subprocess.PIPE,
            env=env,
            cwd=self.agent.cwd or session.cwd or None,
            limit=STDIO_LIMIT,
            **kwargs,
        )
        if proc.stdin is None or proc.stdout is None:
            raise RuntimeError(f"{self.agent.name} did not expose stdio")
        live = _Live()
        live.proc = proc
        live.client = _BridgeClient(session.session_id, self.home)
        live.conn = connect_to_agent(live.client, proc.stdin, proc.stdout)
        live.stderr_task = asyncio.create_task(
            self._drain_stderr(proc, session.session_id, live)
        )
        self._live[session.session_id] = live
        session.pid = proc.pid
        session.pid_create_time = process_create_time(proc.pid) if proc.pid else None
        session.image_name = process_image_name(proc.pid) if proc.pid else None
        if proc.pid:
            record_pid(self.home, session.session_id, proc.pid, session.pid_create_time, session.image_name)
        await self._rpc(
            live.conn.initialize(
                protocol_version=PROTOCOL_VERSION,
                client_info=Implementation(name="agent-bridge", version="0.1.0"),
                client_capabilities=ClientCapabilities(),
            ),
            "initialize",
            session,
        )
        if self.agent.name == "dsh":
            live.applied_model = session.model
            live.applied_effort = dsh_effort(session.effort)
        elif self.agent.name == "cursor":
            live.applied_model = session.model
        return live

    def _new_session_meta(self, session: Session) -> dict[str, Any]:
        base = self.agent.session_meta or None
        if self.agent.name != "grok":
            return dict(base or {})
        return grok_session_meta(base, session.model, session.effort)

    async def _call_new_session(self, conn: Any, cwd: str, meta: dict[str, Any] | None) -> Any:
        extra = dict(meta or {})
        return await conn.new_session(cwd=cwd, mcp_servers=[], **extra)

    async def _call_load_session(self, conn: Any, cwd: str, native_id: str) -> Any:
        if self.agent.name in _RESUME_AGENTS:
            # These workers replay persisted history as session/update
            # notifications before session/load answers. session/resume skips it.
            return await conn.resume_session(
                session_id=native_id,
                cwd=cwd,
                mcp_servers=[],
            )
        return await conn.load_session(
            cwd=cwd,
            session_id=native_id,
            mcp_servers=[],
            noReplay=True,
        )

    async def _call_grok_set_model(
        self,
        conn: Any,
        native_id: str,
        model: str,
        effort: str | None,
    ) -> None:
        params: dict[str, Any] = {"sessionId": native_id, "modelId": model}
        if effort:
            params["_meta"] = {"reasoningEffort": effort}
        sender = getattr(conn, "_conn", None)
        send = getattr(sender, "send_request", None)
        if send is None:
            raise RuntimeError("ACP connection cannot send session/setModel")
        last: Exception | None = None
        for method in GROK_SET_MODEL_METHODS:
            try:
                await send(method, params)
                return
            except Exception as exc:
                last = exc
                code = getattr(exc, "code", None)
                if code != -32601:
                    raise
        if last is not None:
            raise last

    async def _sync_grok_model(self, live: _Live, session: Session) -> None:
        if self.agent.name != "grok" or live.conn is None or not session.native_session_id:
            return
        effort = grok_effort(session.effort)
        model = session.model
        if live.applied_model == model and live.applied_effort == effort:
            return
        if not model:
            if effort and live.applied_effort != effort:
                message = (
                    f"grok effort={effort} ignored on live session "
                    f"{session.session_id} without a model; "
                    "Grok session/setModel needs a modelId"
                )
                log.warning("%s", message)
                live.pending_warnings.append(message)
            return
        await self._rpc(
            self._call_grok_set_model(live.conn, session.native_session_id, model, effort),
            "session/setModel",
            session,
        )
        live.applied_model = model
        live.applied_effort = effort

    def _remember_config_options(self, live: _Live, response: Any) -> None:
        """Cache the `configOptions` snapshot a lifecycle response carries."""
        if self.agent.name not in _CONFIG_OPTION_AGENTS:
            return
        options = getattr(response, "config_options", None)
        if isinstance(options, (list, tuple)):
            live.config_options = list(options)

    async def _set_config_option(
        self,
        live: _Live,
        session: Session,
        config_id: str,
        value: str,
    ) -> None:
        assert live.conn is not None
        response = await self._rpc(
            live.conn.set_config_option(
                config_id=config_id,
                session_id=session.native_session_id,
                value=value,
            ),
            f"session/set_config_option {config_id}",
            session,
        )
        self._remember_config_options(live, response)

    def _remember_applied_model(self, live: _Live, model: str) -> None:
        """Record the live model and drop a stale per-model effort.

        OpenCode (and Kimi thinking) reset the variant when the model
        changes. Keeping ``applied_effort`` from the previous model makes the
        next sync skip the RPC and leave the new model's default in place.
        """
        if live.applied_model != model:
            live.applied_effort = None
        live.applied_model = model

    async def _sync_model_option(self, live: _Live, session: Session) -> None:
        """Apply ``session.model`` through the typed ``model`` config option.

        A model the coordinator named explicitly and that this session does
        not offer must fail the turn, not silently run on the default. The
        error names the real options.
        """
        if not session.model or session.model == live.applied_model:
            return
        current_model, _ = config_option_values(live.config_options, "model")
        if session.model == current_model:
            # Already the session's model (commonly the default a coordinator
            # names explicitly).
            self._remember_applied_model(live, session.model)
            return
        try:
            await self._set_config_option(live, session, "model", session.model)
        except RpcTimeoutError:
            raise
        except Exception as exc:
            _, offered = config_option_values(live.config_options, "model")
            raise RuntimeError(
                f"{self.agent.name} rejected model {session.model!r}; "
                f"session advertises {offered or 'no models'}"
            ) from exc
        self._remember_applied_model(live, session.model)

    async def _sync_bypass_mode(self, live: _Live, session: Session, mode_id: str) -> None:
        """Switch a session that starts in a manual mode to ``mode_id``.

        A missing or rejected mode only warns: ACP ``requestPermission``
        still auto-allows every tool call, so the turn runs either way.
        """
        if live.applied_mode == mode_id:
            return
        current_mode, offered_modes = config_option_values(live.config_options, "mode")
        if current_mode == mode_id:
            live.applied_mode = mode_id
            return
        if offered_modes and mode_id not in offered_modes:
            message = (
                f"{self.agent.name} {mode_id} is not advertised "
                f"(session offers mode {offered_modes}); "
                "ACP requestPermission will auto-allow instead"
            )
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        try:
            await self._rpc(
                live.conn.set_session_mode(
                    session_id=session.native_session_id,
                    mode_id=mode_id,
                ),
                "session/set_mode",
                session,
            )
        except RpcTimeoutError:
            raise
        except Exception as exc:
            message = (
                f"{self.agent.name} rejected mode={mode_id}: {exc}; "
                "ACP requestPermission will auto-allow instead"
            )
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        live.applied_mode = mode_id

    async def _sync_kimi_selection(self, live: _Live, session: Session) -> None:
        """Force yolo mode, then apply model and thinking for a Kimi session.

        Kimi accepts no ``session/new`` hints: a fresh session lands in
        ``default`` mode (approval per tool call) on the configured default
        model. Mode, model and thinking are all set afterwards through the
        typed ACP config surface, whose responses carry the refreshed option
        snapshot — that snapshot is how the next turn knows it has nothing to
        change.
        """
        if self.agent.name != "kimi" or live.conn is None or not session.native_session_id:
            return
        if live.applied_mode != KIMI_MODE_YOLO:
            await self._rpc(
                live.conn.set_session_mode(
                    session_id=session.native_session_id,
                    mode_id=KIMI_MODE_YOLO,
                ),
                "session/set_mode",
                session,
            )
            live.applied_mode = KIMI_MODE_YOLO
        await self._sync_model_option(live, session)
        # Order matters: thinking vocabularies are per model, and the set above
        # refreshed the snapshot this reads.
        await self._sync_kimi_thinking(live, session)

    async def _sync_kimi_thinking(self, live: _Live, session: Session) -> None:
        if not session.effort:
            return
        current, offered = config_option_values(live.config_options, "thinking")
        level = resolve_kimi_thinking(session.effort, offered)
        if level is None:
            message = (
                f"kimi effort={session.effort} has no counterpart on "
                f"{live.applied_model or 'the current model'}; "
                f"session advertises thinking {offered or '(none)'}"
            )
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        if level == current:
            live.applied_effort = level
            return
        try:
            await self._set_config_option(live, session, "thinking", level)
        except RpcTimeoutError:
            raise
        except Exception as exc:
            # Bridge chose this level by mapping, so a rejection is Bridge's
            # problem to report; the turn still runs on the model's default.
            message = f"kimi rejected thinking={level} for effort={session.effort}: {exc}"
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        live.applied_effort = level

    async def _sync_opencode_selection(self, live: _Live, session: Session) -> None:
        """Apply model and variant for an OpenCode ACP session.

        OpenCode has no product login and no yolo mode on the ACP path.
        Permissions go through requestPermission (Bridge auto-picks
        allow-always). Model is ``provider/model``; effort is the current
        model's variants and may be absent entirely.
        """
        if self.agent.name != "opencode" or live.conn is None or not session.native_session_id:
            return
        await self._sync_model_option(live, session)
        await self._sync_opencode_effort(live, session)

    async def _sync_opencode_effort(self, live: _Live, session: Session) -> None:
        if not session.effort:
            return
        current, offered = config_option_values(live.config_options, "effort")
        level = resolve_opencode_effort(session.effort, offered)
        if level is None:
            message = (
                f"opencode effort={session.effort} has no counterpart on "
                f"{live.applied_model or 'the current model'}; "
                f"session advertises effort {offered or '(none)'}"
            )
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        if level == current:
            live.applied_effort = level
            return
        try:
            await self._set_config_option(live, session, "effort", level)
        except RpcTimeoutError:
            raise
        except Exception as exc:
            message = f"opencode rejected effort={level} for effort={session.effort}: {exc}"
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        live.applied_effort = level

    async def _sync_claude_selection(self, live: _Live, session: Session) -> None:
        """Force bypassPermissions, then apply model and effort for Claude Code.

        Product ``claude`` is not an ACP server. The worker is
        ``claude-agent-acp``, which starts in ``default`` (manual) mode.
        Mode, model and effort are set afterwards through the typed ACP
        surface. ``session/load`` replays history; Bridge uses resume.
        """
        if self.agent.name != "claude" or live.conn is None or not session.native_session_id:
            return
        await self._sync_bypass_mode(live, session, CLAUDE_MODE_BYPASS)
        await self._sync_model_option(live, session)
        await self._sync_claude_effort(live, session)

    async def _sync_devin_selection(self, live: _Live, session: Session) -> None:
        """Force bypass, then apply the model for a Devin CLI session.

        ``devin acp`` starts every session in ``accept-edits`` regardless of
        ``DEVIN_PERMISSION_MODE``. Model ids already carry the level
        (``swe-1-7-medium``, ``claude-opus-5-high``); there is no effort
        option, so a Bridge effort is reported as ignored once per value.
        """
        if self.agent.name != "devin" or live.conn is None or not session.native_session_id:
            return
        await self._sync_bypass_mode(live, session, DEVIN_MODE_BYPASS)
        await self._sync_model_option(live, session)
        if session.effort and live.applied_effort != session.effort:
            message = (
                f"devin has no effort option; effort={session.effort} ignored. "
                "Pick a model id that carries the level instead "
                "(e.g. swe-1-7-medium, claude-opus-5-high)"
            )
            log.warning("%s", message)
            live.pending_warnings.append(message)
            live.applied_effort = session.effort

    async def _sync_selection(self, live: _Live, session: Session) -> None:
        await self._sync_grok_model(live, session)
        await self._sync_kimi_selection(live, session)
        await self._sync_opencode_selection(live, session)
        await self._sync_claude_selection(live, session)
        await self._sync_devin_selection(live, session)

    async def _sync_claude_effort(self, live: _Live, session: Session) -> None:
        if not session.effort:
            return
        current, offered = config_option_values(live.config_options, "effort")
        level = resolve_claude_effort(session.effort, offered)
        if level is None:
            message = (
                f"claude effort={session.effort} has no counterpart on "
                f"{live.applied_model or 'the current model'}; "
                f"session advertises effort {offered or '(none)'}"
            )
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        if level == current:
            live.applied_effort = level
            return
        try:
            await self._set_config_option(live, session, "effort", level)
        except RpcTimeoutError:
            raise
        except Exception as exc:
            message = f"claude rejected effort={level} for effort={session.effort}: {exc}"
            log.warning("%s", message)
            live.pending_warnings.append(message)
            return
        live.applied_effort = level

    async def ensure_session(self, session: Session) -> None:
        live = self._live.get(session.session_id)
        if (
            live
            and live.proc
            and live.proc.returncode is None
            and live.conn is not None
            and session.native_session_id
        ):
            if self.agent.name == "dsh" and dsh_needs_respawn(
                live.applied_model,
                live.applied_effort,
                session.model,
                session.effort,
            ):
                log.info(
                    "dsh model/effort changed (%s/%s -> %s/%s); respawning ACP process",
                    live.applied_model,
                    live.applied_effort,
                    session.model,
                    dsh_effort(session.effort),
                )
                session.native_session_id = None
                await self.shutdown(session)
            else:
                await self._sync_selection(live, session)
                return
        live = await self._spawn(session)
        native = session.native_session_id
        if native and self.can_revive():
            try:
                revived = await self._rpc(
                    self._call_load_session(live.conn, session.cwd, native),
                    "session/resume" if self.agent.name in _RESUME_AGENTS else "session/load",
                    session,
                )
            except RpcTimeoutError:
                # The worker is already dead; a new_session on the same
                # connection cannot succeed.
                raise
            except Exception:
                log.warning("session/load failed for %s; creating a new session", session.session_id, exc_info=True)
            else:
                self._remember_config_options(live, revived)
                await self._sync_selection(live, session)
                return
        created = await self._rpc(
            self._call_new_session(live.conn, session.cwd, self._new_session_meta(session)),
            "session/new",
            session,
        )
        session.native_session_id = created.session_id
        self._remember_config_options(live, created)
        if self.agent.name == "grok":
            # Grok /new applies the _meta reasoningEffort but always lands on
            # the campaign default model. Record the effort as applied so an
            # effort-only dispatch does not raise a spurious warning, and let
            # _sync_grok_model switch the model via session/setModel.
            live.applied_effort = grok_effort(session.effort)
        await self._sync_selection(live, session)

    async def run_turn(self, session: Session, task: Task) -> TurnResult:
        await self.ensure_session(session)
        live = self._live[session.session_id]
        assert live.conn is not None and live.client is not None
        live.client.reset_turn()
        live.stderr_tail = ""
        warnings: list[str] = live.pending_warnings
        live.pending_warnings = []
        if self.agent.name == "cursor" and task.effort:
            warnings.append(
                "cursor has no separate effort setting; select the exact model ID "
                f"that includes the desired effort; effort={task.effort!r} was ignored"
            )
        elif self.agent.name not in _MODEL_EFFORT_AGENTS and (task.model or task.effort):
            warnings.append(
                f"{self.agent.name} has no model/effort selection; "
                f"model={task.model!r} effort={task.effort!r} were ignored"
            )
        append_event(session.session_id, "prompt_sent", {"text": task.message}, self.home)
        prompt = live.conn.prompt(
            session_id=session.native_session_id,
            prompt=[text_block(task.message)],
        )
        live.prompt_task = asyncio.ensure_future(prompt)
        try:
            response = await live.prompt_task
        except asyncio.CancelledError:
            append_event(session.session_id, "turn_end", {"stop_reason": "cancelled"}, self.home)
            return TurnResult(
                text="".join(live.client.text_parts),
                files_changed=sorted(live.client.files),
                stop_reason="cancelled",
                warnings=warnings,
                observed_model=live.applied_model,
                observed_effort=live.applied_effort,
            )
        except Exception:
            if live.stderr_tail:
                log.warning(
                    "%s prompt failed for %s stderr_tail=%r",
                    self.agent.name,
                    session.session_id,
                    live.stderr_tail,
                )
            raise
        finally:
            live.prompt_task = None
        stop = getattr(response, "stop_reason", None) or "end_turn"
        if hasattr(stop, "value"):
            stop = stop.value
        stop = str(stop)
        usage = live.client.usage
        if not usage:
            dumped_usage = _dump(getattr(response, "usage", None))
            if isinstance(dumped_usage, dict):
                usage = dumped_usage
        append_event(session.session_id, "turn_end", {"stop_reason": stop}, self.home)
        return TurnResult(
            text="".join(live.client.text_parts),
            files_changed=sorted(live.client.files),
            stop_reason=stop,
            usage=usage,
            native_session_id=session.native_session_id,
            warnings=warnings,
            observed_model=live.applied_model,
            observed_effort=live.applied_effort,
        )

    async def cancel(self, session: Session) -> None:
        live = self._live.get(session.session_id)
        if live is None or live.conn is None:
            return
        try:
            await asyncio.wait_for(live.conn.cancel(session_id=session.native_session_id), timeout=5)
        except Exception:
            log.warning("ACP cancel failed for %s", session.session_id, exc_info=True)
        if live.prompt_task is not None:
            try:
                await asyncio.wait_for(asyncio.shield(live.prompt_task), timeout=10)
                return
            except (asyncio.CancelledError, Exception):
                # CancelledError derives from BaseException and must be
                # listed explicitly; a cancelled prompt is the normal case.
                pass
        if live.proc is not None:
            await reap_subprocess(live.proc)
            await self.shutdown(session)

    async def shutdown(self, session: Session) -> None:
        live = self._live.pop(session.session_id, None)
        if live is None:
            drop_pid(self.home, session.session_id)
            session.pid = None
            return
        if live.conn is not None:
            with contextlib.suppress(Exception):
                await asyncio.wait_for(live.conn.close(), timeout=2)
        if live.proc is not None:
            await reap_subprocess(live.proc)
        if live.stderr_task is not None:
            if not live.stderr_task.done():
                live.stderr_task.cancel()
            with contextlib.suppress(asyncio.CancelledError):
                await live.stderr_task
        drop_pid(self.home, session.session_id)
        session.pid = None
