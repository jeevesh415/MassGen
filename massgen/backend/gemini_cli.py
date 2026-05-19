"""
Gemini CLI Backend - subprocess wrapper for @google/gemini-cli.

Auth: CLI login (gemini) first, then GOOGLE_API_KEY/GEMINI_API_KEY.
Session persistence via -r <session_id>. MCP tools via .gemini/settings.json.
Requires: npm install -g @google/gemini-cli
"""

from __future__ import annotations

import asyncio
import json
import os
import re
import shlex
import shutil
import sys
import time
import uuid
from collections.abc import AsyncGenerator
from pathlib import Path
from typing import Any

from ..logger_config import get_event_emitter, logger
from ._streaming_buffer_mixin import StreamingBufferMixin
from .base import (
    FilesystemSupport,
    LLMBackend,
    StreamChunk,
    get_multimodal_tool_definitions,
    parse_workflow_tool_calls,
)
from .native_tool_mixin import NativeToolBackendMixin

GEMINI_CLI_DEFAULT_MODEL = "gemini-3.1-pro-preview"
GEMINI_CLI_KNOWN_MODELS = [
    "gemini-2.5-pro",
    "gemini-2.5-flash",
    "gemini-2.5-flash-lite",
    "gemini-3-flash-preview",
    "gemini-3.1-pro-preview",
]
GEMINI_WORKFLOW_MAX_SESSION_TURNS = 50
GEMINI_FAIL_FAST_QUOTA_RETRY_THRESHOLD = 4
GEMINI_FAIL_FAST_NETWORK_RETRY_THRESHOLD = 3
GEMINI_FAIL_FAST_TOTAL_RETRY_THRESHOLD = 5

_RE_CURRENT_ANSWERS = re.compile(
    r"<CURRENT ANSWERS from the agents>(.*?)<END OF CURRENT ANSWERS>",
    re.IGNORECASE | re.DOTALL,
)
_RE_AGENT_TAG = re.compile(r"<agent[^>]*>", re.IGNORECASE)


class GeminiCLIBackend(NativeToolBackendMixin, StreamingBufferMixin, LLMBackend):
    """Gemini CLI backend using subprocess with stream-json event parsing.

    Provides streaming interface to Gemini CLI with login-first auth and
    session persistence. Uses `gemini -p <prompt> --output-format stream-json`.
    """

    def __init__(self, api_key: str | None = None, **kwargs):
        super().__init__(api_key, **kwargs)
        # The base class may have injected the command_line MCP server (when
        # enable_mcp_command_line=True). In Docker mode the CLI runs *inside*
        # the container, so the MCP server script (a host-only path) and the
        # massgen package (not installed in the container) are both unavailable.
        # Remove it here; Gemini CLI's built-in tools cover all execution needs.
        if kwargs.get("command_line_execution_mode") == "docker":
            self._remove_injected_command_line_mcp()
        self.__init_native_tool_mixin__()
        self._init_native_hook_adapter(
            "massgen.mcp_tools.native_hook_adapters.GeminiCLINativeHookAdapter",
        )
        self._hook_sequence = 0

        self.approval_mode = kwargs.get("approval_mode", "yolo")

        configured_env = self._get_configured_credentials_env()
        self.api_key = api_key or os.getenv("GEMINI_API_KEY") or os.getenv("GOOGLE_API_KEY") or configured_env.get("GEMINI_API_KEY") or configured_env.get("GOOGLE_API_KEY")
        self.use_login = not bool(self.api_key)

        self.session_id: str | None = None

        self.model = kwargs.get("model", GEMINI_CLI_DEFAULT_MODEL)
        if self.model not in GEMINI_CLI_KNOWN_MODELS:
            logger.warning(
                f"Gemini CLI: model '{self.model}' not in known models list " f"{GEMINI_CLI_KNOWN_MODELS}. It may not be supported.",
            )
        self._config_cwd = kwargs.get("cwd")

        # Wire hook_dir on the adapter now that cwd is known
        adapter = self.get_native_hook_adapter()
        if adapter and hasattr(adapter, "hook_dir"):
            adapter.hook_dir = self._workspace_config_dir()

        self.system_prompt = kwargs.get("system_prompt", "")
        configured_mcp_servers = kwargs.get("mcp_servers", [])
        self.mcp_servers = list(configured_mcp_servers) if isinstance(configured_mcp_servers, list) else []
        self._managed_workspace_dirs: set[Path] = set()
        self._managed_workspace_file_backups: dict[Path, tuple[bool, bytes | None]] = {}
        self._pending_workflow_instructions = ""
        self._tool_call_context: dict[str, dict[str, Any]] = {}
        self._tool_start_times: dict[str, float] = {}
        self._workflow_call_mode = "any"
        self._workflow_call_emitted_this_turn = False
        self._workflow_mcp_active = False
        self._stop_after_first_workflow_call = False
        self._last_turn_missing_workflow_call = False

        self.agent_id = kwargs.get("agent_id")

        self._docker_execution = kwargs.get("command_line_execution_mode") == "docker"
        self._docker_gemini_verified = False
        # Tell the native hook adapter to use container-safe paths when in Docker mode.
        adapter = self.get_native_hook_adapter()
        if adapter and hasattr(adapter, "docker_mode"):
            adapter.docker_mode = self._docker_execution

        custom_tools = list(kwargs.get("custom_tools", []))
        enable_multimodal = self.config.get("enable_multimodal_tools", False) or kwargs.get("enable_multimodal_tools", False)
        if enable_multimodal:
            custom_tools.extend(get_multimodal_tool_definitions())
            logger.info("Gemini CLI backend: multimodal tools enabled (read_media, generate_media)")

        if custom_tools:
            self._setup_custom_tools_mcp(custom_tools)

        if self._docker_execution:
            self._gemini_path = "gemini"
        else:
            self._gemini_path = self._find_gemini_cli()
            if not self._gemini_path:
                raise RuntimeError(
                    "Gemini CLI not found. Install it using one of:\n"
                    "  npm install -g @google/gemini-cli\n"
                    "  brew install gemini-cli             (macOS/Linux)\n"
                    "  sudo port install gemini-cli        (macOS via MacPorts)\n"
                    "  npx @google/gemini-cli              (run without installing)\n"
                    "Then verify with: gemini --version",
                )

        if self.use_login and not self._has_cached_credentials():
            logger.warning(
                "No API key or cached Gemini CLI login found. " "Authentication will be required on first use (run `gemini` to login).",
            )

    def _remove_injected_command_line_mcp(self) -> None:
        """Remove the command_line MCP server injected by the base class, if present."""
        mcp_servers = self.config.get("mcp_servers")
        if not mcp_servers:
            return
        if isinstance(mcp_servers, list):
            filtered = [s for s in mcp_servers if not (isinstance(s, dict) and s.get("name") == "command_line")]
            if len(filtered) < len(mcp_servers):
                self.config["mcp_servers"] = filtered
                logger.info("Gemini CLI Docker mode: removed command_line MCP server (host-only paths not available in container)")
        elif isinstance(mcp_servers, dict) and "command_line" in mcp_servers:
            del mcp_servers["command_line"]
            logger.info("Gemini CLI Docker mode: removed command_line MCP server (host-only paths not available in container)")

    @property
    def cwd(self) -> str:
        """Resolve the working directory."""
        if self.filesystem_manager:
            return str(Path(str(self.filesystem_manager.get_current_workspace())).resolve())
        return self._config_cwd or os.getcwd()

    def _workspace_config_dir(self) -> Path:
        """Return the project-scoped Gemini CLI config directory."""
        return Path(self.cwd) / ".gemini"

    def _ensure_workspace_config_dir(self) -> Path:
        """Create and track the workspace config directory when needed."""
        config_dir = self._workspace_config_dir()
        if not config_dir.exists():
            config_dir.mkdir(parents=True, exist_ok=True)
            self._managed_workspace_dirs.add(config_dir.resolve())
        return config_dir

    def _track_managed_workspace_file(self, path: Path) -> Path:
        """Snapshot a workspace file before the backend overwrites it."""
        tracked_path = path.resolve()
        if tracked_path in self._managed_workspace_file_backups:
            return tracked_path

        existed_before = tracked_path.exists()
        original_bytes: bytes | None = None
        if existed_before:
            try:
                original_bytes = tracked_path.read_bytes()
            except OSError as exc:
                raise RuntimeError(
                    f"Gemini CLI cannot safely manage existing workspace file {tracked_path}: {exc}",
                ) from exc

        self._managed_workspace_file_backups[tracked_path] = (existed_before, original_bytes)
        return tracked_path

    def _prune_managed_workspace_dirs(self) -> None:
        """Remove empty config directories created by this backend."""
        for config_dir in sorted(self._managed_workspace_dirs, key=lambda p: len(p.parts), reverse=True):
            try:
                if config_dir.exists() and not any(config_dir.iterdir()):
                    config_dir.rmdir()
                    self._managed_workspace_dirs.discard(config_dir)
            except OSError:
                continue

    def _restore_managed_workspace_file(self, path: Path) -> None:
        """Restore or remove a workspace file that this backend previously managed."""
        tracked_path = path.resolve()
        snapshot = self._managed_workspace_file_backups.pop(tracked_path, None)
        if snapshot is None:
            return

        existed_before, original_bytes = snapshot
        try:
            if existed_before:
                tracked_path.parent.mkdir(parents=True, exist_ok=True)
                tracked_path.write_bytes(original_bytes or b"")
            elif tracked_path.exists():
                tracked_path.unlink()
        except OSError as exc:
            logger.warning(f"Failed to restore Gemini CLI workspace file {tracked_path}: {exc}")

        self._prune_managed_workspace_dirs()

    def _remove_runtime_mcp_server(self, server_name: str) -> None:
        """Remove one runtime-managed MCP server from the per-backend list."""
        self.mcp_servers = [server for server in self.mcp_servers if not (isinstance(server, dict) and server.get("name") == server_name)]

    def _find_gemini_cli(self) -> str | None:
        """Find the Gemini CLI executable."""
        gemini_path = shutil.which("gemini")
        if gemini_path:
            return gemini_path
        npm_paths = [
            Path.home() / ".npm-global" / "bin" / "gemini",
            Path.home() / ".nvm" / "versions" / "node" / "current" / "bin" / "gemini",
            Path("/usr/local/bin/gemini"),
            Path.home() / "node_modules" / ".bin" / "gemini",
        ]
        if os.name == "nt":
            for env_var in ("APPDATA", "LOCALAPPDATA"):
                base = os.environ.get(env_var)
                if base:
                    npm_paths.append(Path(base) / "npm" / "gemini.cmd")
                    npm_paths.append(Path(base) / "npm" / "gemini")
        for path in npm_paths:
            if path.exists():
                return str(path)
        return None

    def _has_cached_credentials(self) -> bool:
        """Check if Gemini CLI has cached login (Google account or API key in env)."""
        if self.api_key:
            return True
        gemini_home = Path.home() / ".gemini"
        return (gemini_home / "google_accounts.json").exists() or (gemini_home / "oauth_creds.json").exists()

    async def _ensure_authenticated(self) -> None:
        """Ensure Gemini CLI is authenticated before making requests."""
        if self.api_key:
            return
        if self._has_cached_credentials():
            return
        raise RuntimeError(
            "Gemini CLI not authenticated. Run `gemini` interactively to login with Google, " "or set GOOGLE_API_KEY or GEMINI_API_KEY environment variable.",
        )

    def _build_subprocess_env(self, base_env: dict[str, str] | None = None) -> dict[str, str]:
        """Build environment dict for subprocess execution with API key injection."""
        env = dict(os.environ if base_env is None else base_env)

        # Always set GEMINI_HOME so Gemini CLI reads settings.json (hooks,
        # MCP servers) from the workspace .gemini/ dir, not ~/.gemini/.
        workspace_gemini = str(self._workspace_config_dir())
        env["GEMINI_HOME"] = workspace_gemini

        if self._docker_execution:
            env.update(self._get_configured_credentials_env())

        if os.name == "nt":
            env.setdefault("PATHEXT", ".COM;.EXE;.BAT;.CMD")
            env.setdefault("COMSPEC", r"C:\Windows\System32\cmd.exe")

            path_value = env.get("PATH", "")
            if not shutil.which("node", path=path_value):
                program_files = os.environ.get("ProgramFiles", r"C:\Program Files")
                node_dir = Path(program_files) / "nodejs"
                if (node_dir / "node.exe").exists():
                    env["PATH"] = f"{node_dir};{path_value}" if path_value else str(node_dir)
                    logger.info(f"Gemini CLI: node not found on PATH; prepended {node_dir}")
                else:
                    logger.warning(
                        "Gemini CLI: node not found on PATH and default node location missing: " f"{node_dir}",
                    )

        env["NO_COLOR"] = "1"
        if self.api_key:
            env["GEMINI_API_KEY"] = self.api_key
            env["GOOGLE_API_KEY"] = self.api_key
        return env

    def _resolve_fastmcp_command(self) -> str:
        """Resolve FastMCP executable path for local Gemini CLI MCP servers."""
        if self._docker_execution:
            return "fastmcp"

        resolved = shutil.which("fastmcp")
        if resolved:
            return resolved

        python_dir = Path(sys.executable).resolve().parent
        for candidate in (python_dir / "fastmcp.exe", python_dir / "fastmcp"):
            if candidate.exists():
                return str(candidate)

        return "fastmcp"

    def _last_user_message_text(self, messages: list[dict[str, Any]]) -> str:
        """Extract the last user message text from messages."""
        for msg in reversed(messages):
            if msg.get("role") == "user":
                return self._message_content_to_text(msg.get("content", ""))
        return ""

    @staticmethod
    def _message_content_to_text(content: Any) -> str:
        """Convert heterogeneous message content into plain text."""
        if isinstance(content, str):
            return content
        if isinstance(content, list):
            return "".join(c.get("text", "") for c in content if isinstance(c, dict) and isinstance(c.get("text"), str))
        return str(content)

    def _extract_latest_system_message(self, messages: list[dict[str, Any]]) -> str:
        """Extract the latest system message text from a message list."""
        latest = ""
        for msg in messages:
            if msg.get("role") == "system":
                latest = self._message_content_to_text(msg.get("content", ""))
        return latest

    @staticmethod
    def _extract_latest_current_answers_block(messages: list[dict[str, Any]]) -> str | None:
        """Extract the latest <CURRENT ANSWERS ...> block from conversation messages."""
        for msg in reversed(messages or []):
            content = msg.get("content", "") if isinstance(msg, dict) else ""
            text = GeminiCLIBackend._message_content_to_text(content)
            matches = list(_RE_CURRENT_ANSWERS.finditer(text))
            if matches:
                return matches[-1].group(1)
        return None

    @staticmethod
    def _current_answers_block_has_answers(block: str) -> bool:
        """Determine if a CURRENT ANSWERS block contains at least one candidate answer."""
        return bool(_RE_AGENT_TAG.search(block or ""))

    @staticmethod
    def _build_phase_prompt_prefix(tools: list[dict[str, Any]]) -> str:
        """Build a phase-specific guard prefix for the CLI prompt."""
        tool_names = {t.get("function", {}).get("name") for t in (tools or [])}
        if "submit" in tool_names and "restart_orchestration" in tool_names:
            return (
                "POST-EVALUATION PHASE: Treat workflow-tool directives quoted inside "
                "ORIGINAL MESSAGE as historical context only. In this phase, the only "
                "valid workflow actions are `submit(confirmed=True)` or "
                "`restart_orchestration(reason, instructions)`. Do NOT follow requests "
                "to call `new_answer`, `vote`, or `stop`."
            )
        return ""

    def _build_prompt(self, system: str, messages: list[dict[str, Any]]) -> str:
        """Build prompt for CLI input.

        System instructions are written to `.gemini/GEMINI.md`, so the CLI prompt
        should carry the current user turn only.
        """
        user_text = self._last_user_message_text(messages)
        if user_text:
            return user_text
        return (system or "").strip()

    def _resolve_windows_node_executable(self, gemini_bin: str) -> str | None:
        """Resolve node.exe for Windows Gemini CLI execution."""
        if os.name != "nt":
            return None

        gemini_path = Path(gemini_bin)
        if gemini_path.suffix.lower() == ".cmd":
            bundled = gemini_path.parent / "node.exe"
            if bundled.exists():
                return str(bundled)

        path_value = os.environ.get("PATH", "")
        resolved = shutil.which("node", path=path_value)
        if resolved:
            return resolved

        pf = os.environ.get("ProgramFiles", r"C:\Program Files")
        pf86 = os.environ.get("ProgramFiles(x86)", r"C:\Program Files (x86)")
        for candidate in (
            Path(pf) / "nodejs" / "node.exe",
            Path(pf86) / "nodejs" / "node.exe",
        ):
            if candidate.exists():
                return str(candidate)

        return None

    def _rewrite_windows_gemini_cmd_to_node(self, cmd: list[str]) -> list[str]:
        """Bypass fragile .cmd resolution by invoking Gemini JS with node directly."""
        if os.name != "nt" or not cmd:
            return cmd

        gemini_path = Path(cmd[0])
        if gemini_path.suffix.lower() != ".cmd":
            return cmd

        js_entry = gemini_path.parent / "node_modules" / "@google" / "gemini-cli" / "dist" / "index.js"
        node_exe = self._resolve_windows_node_executable(str(gemini_path))
        if not node_exe or not js_entry.exists():
            return cmd

        logger.info("Gemini CLI: using direct node launch path for Windows .cmd wrapper")
        return [node_exe, "--no-warnings=DEP0040", str(js_entry), *cmd[1:]]

    def _build_exec_command(
        self,
        prompt: str,
        resume_session: bool = False,
        for_docker: bool = False,
    ) -> list[str]:
        """Build the gemini CLI command."""
        gemini_bin = "gemini" if for_docker else self._gemini_path
        cmd = [gemini_bin, "-m", self.model]
        if resume_session and self.session_id:
            cmd.extend(["-r", self.session_id])
        cmd.extend(["--output-format", "stream-json"])
        if self.approval_mode:
            cmd.extend(["--approval-mode", self.approval_mode])
        cmd.extend(["--prompt", prompt])
        return self._rewrite_windows_gemini_cmd_to_node(cmd)

    def _infer_workflow_call_mode(self, messages: list[dict[str, Any]], tools: list[dict[str, Any]]) -> str:
        """Infer workflow call constraints from current turn context.

        Prefer structured context over phrase heuristics. In no-answer rounds,
        `vote` cannot succeed, so restrict to `new_answer` to avoid dead-end retries.
        """
        tool_names = {t.get("function", {}).get("name") for t in (tools or [])}
        if "vote" not in tool_names or "new_answer" not in tool_names:
            return "any"

        current_answers_block = self._extract_latest_current_answers_block(messages)
        if current_answers_block is not None:
            if self._current_answers_block_has_answers(current_answers_block):
                return "any"
            return "new_answer_only"

        # Retry-sticky guard: when previous mode was no-answer, keep vote hidden
        # until a CURRENT ANSWERS block explicitly shows answer candidates.
        if self._workflow_call_mode == "new_answer_only":
            return "new_answer_only"

        return "any"

    @staticmethod
    def _filter_workflow_tools_for_mode(
        tools: list[dict[str, Any]],
        workflow_call_mode: str,
    ) -> list[dict[str, Any]]:
        """Filter workflow tool exposure based on current round constraints.

        In no-answer rounds, keep `new_answer` but hide `vote` from Gemini's MCP
        workflow server to avoid presenting an invalid action.
        """
        if workflow_call_mode != "new_answer_only":
            return list(tools or [])

        filtered: list[dict[str, Any]] = []
        for tool in tools or []:
            name = tool.get("function", {}).get("name") or tool.get("name")
            if name == "vote":
                continue
            filtered.append(tool)
        return filtered

    @staticmethod
    def _normalize_tool_name(tool_name: Any) -> str:
        """Normalize tool names across providers/CLI event shapes."""
        if not isinstance(tool_name, str):
            return ""
        return tool_name.rsplit("/", 1)[-1]

    @staticmethod
    def _filter_workflow_tool_calls_for_mode(
        tool_calls: list[dict[str, Any]],
        workflow_call_mode: str,
    ) -> list[dict[str, Any]]:
        """Filter parsed workflow tool call payloads based on round mode."""
        if workflow_call_mode != "new_answer_only":
            return list(tool_calls or [])

        filtered_calls: list[dict[str, Any]] = []
        for tool_call in tool_calls or []:
            function = tool_call.get("function", {}) if isinstance(tool_call, dict) else {}
            name = ""
            if isinstance(function, dict):
                name = function.get("name", "")
            if not name and isinstance(tool_call, dict):
                name = tool_call.get("name", "")
            if name == "vote":
                continue
            filtered_calls.append(tool_call)
        return filtered_calls

    @staticmethod
    def _safe_json_loads(value: Any) -> dict[str, Any] | None:
        """Best-effort JSON object loader."""
        if isinstance(value, dict):
            return value
        if isinstance(value, str):
            try:
                loaded = json.loads(value)
                return loaded if isinstance(loaded, dict) else None
            except json.JSONDecodeError:
                return None
        return None

    @classmethod
    def _extract_json_objects(cls, payload: Any) -> list[dict[str, Any]]:
        """Extract possible JSON objects from diverse Gemini tool_result payloads."""
        objects: list[dict[str, Any]] = []

        if isinstance(payload, dict):
            objects.append(payload)
            content = payload.get("content")
            if isinstance(content, list):
                for item in content:
                    if isinstance(item, dict) and isinstance(item.get("text"), str):
                        parsed = cls._safe_json_loads(item.get("text"))
                        if parsed:
                            objects.append(parsed)
        elif isinstance(payload, list):
            for item in payload:
                objects.extend(cls._extract_json_objects(item))
        elif isinstance(payload, str):
            parsed = cls._safe_json_loads(payload)
            if parsed:
                objects.append(parsed)

        return objects

    @staticmethod
    def _normalize_arguments(arguments: Any) -> dict[str, Any]:
        """Normalize tool argument payload to a dictionary."""
        if isinstance(arguments, dict):
            return arguments
        if isinstance(arguments, str):
            try:
                loaded = json.loads(arguments)
                if isinstance(loaded, dict):
                    return loaded
            except json.JSONDecodeError:
                return {}
        return {}

    def _try_extract_workflow_tool_call_from_result(self, event: dict[str, Any]) -> dict[str, Any] | None:
        """Extract workflow tool call from Gemini tool_result event payload."""
        from ..mcp_tools.workflow_tools_server import extract_workflow_tool_call
        from ..tool.workflow_toolkits.base import WORKFLOW_TOOL_NAMES

        candidates: list[Any] = []
        for key in ("result", "tool_result", "output", "content", "response", "data", "message"):
            if key in event:
                candidates.append(event.get(key))

        tool_call_id = event.get("id") or event.get("tool_id") or event.get("toolId")
        if tool_call_id and tool_call_id in self._tool_call_context:
            context = self._tool_call_context[tool_call_id]
            if context.get("result") is not None:
                candidates.append(context.get("result"))

        for candidate in candidates:
            for obj in self._extract_json_objects(candidate):
                extracted = extract_workflow_tool_call(obj)
                if extracted:
                    return extracted

        # Fallback for providers that emit explicit tool_result fields without the
        # workflow server wrapper shape.
        tool_name = self._normalize_tool_name(event.get("name") or event.get("tool_name") or event.get("toolName"))
        if tool_call_id and tool_call_id in self._tool_call_context:
            tool_name = self._normalize_tool_name(tool_name or self._tool_call_context[tool_call_id].get("name"))

        if tool_name in WORKFLOW_TOOL_NAMES:
            args = self._normalize_arguments(event.get("arguments"))
            if not args:
                args = self._normalize_arguments(event.get("parameters"))
            if not args and tool_call_id and tool_call_id in self._tool_call_context:
                args = self._tool_call_context[tool_call_id].get("arguments", {})
            return {
                "id": f"call_{uuid.uuid4().hex[:8]}",
                "type": "function",
                "function": {"name": tool_name, "arguments": args},
            }

        return None

    @staticmethod
    def _truncate_line(line: str, max_chars: int = 200) -> str:
        """Truncate long debug lines to avoid noisy status chunks."""
        if len(line) <= max_chars:
            return line
        return f"{line[:max_chars]}..."

    @staticmethod
    def _is_quota_error_text(text: str) -> bool:
        """Detect Gemini capacity/quota exhaustion messages."""
        lowered = (text or "").lower()
        indicators = (
            "terminalquotaerror",
            "exhausted your capacity",
            "quota will reset",
            "resource_exhausted",
            "code: 429",
            "too many requests",
            "rate limit exceeded",
        )
        return any(token in lowered for token in indicators)

    @staticmethod
    def _is_auth_error_text(text: str) -> bool:
        """Detect Gemini authentication/login/API-key failures."""
        lowered = (text or "").lower()
        indicators = (
            "gemini cli not authenticated",
            "not authenticated",
            "authentication required",
            "failed to authenticate",
            "please login",
            "please log in",
            "login required",
            "log in with google",
            "login with google",
            "set google_api_key",
            "set gemini_api_key",
            "google_api_key or gemini_api_key",
            "no api key",
            "missing api key",
            "unauthenticated",
        )
        return any(token in lowered for token in indicators)

    def _build_error_chunk(self, message: str) -> StreamChunk:
        """Normalize Gemini errors and mark fatal auth failures explicitly."""
        normalized = self._normalize_gemini_error_message(message)
        status = "fatal" if self._is_auth_error_text(message) or self._is_auth_error_text(normalized) else None
        return StreamChunk(type="error", error=normalized, status=status)

    def _normalize_gemini_error_message(self, message: str) -> str:
        """Normalize Gemini errors into actionable messages for orchestration."""
        if self._is_quota_error_text(message):
            return "Gemini CLI quota/capacity exhausted (HTTP 429). " "Retry after quota reset or switch to a model with available capacity."
        if self._is_auth_error_text(message):
            return "Gemini CLI authentication unavailable. Run `gemini` interactively to login with Google, " "or set GOOGLE_API_KEY or GEMINI_API_KEY. This failure is non-retryable."
        return message

    def _build_exit_error_message(self, exit_code: int, non_json_lines: list[str] | None = None) -> str:
        """Build a clearer error message for known Gemini CLI exit codes."""
        explanations = {
            42: "Gemini CLI input error (invalid arguments or malformed request).",
            53: "Gemini CLI turn limit exceeded (max turns reached).",
        }
        base = explanations.get(exit_code, f"Gemini CLI exited with code {exit_code}")

        if non_json_lines:
            joined = "\n".join(non_json_lines[-10:])
            if self._is_auth_error_text(joined) or self._is_quota_error_text(joined):
                return self._normalize_gemini_error_message(joined)

        if self.approval_mode == "yolo" and non_json_lines:
            joined = "\n".join(non_json_lines[-3:]).lower()
            if "yolo" in joined and ("disable" in joined or "not allowed" in joined or "forbidden" in joined):
                return "Gemini CLI rejected '--approval-mode yolo'. " "Update backend.approval_mode or CLI security settings."

        if non_json_lines:
            joined = "\n".join(non_json_lines[-10:]).lower()
            if "attachconsole failed" in joined or "conpty_console_list_agent.js" in joined:
                return (
                    f"{base}. Gemini CLI shell helper failed to attach to a Windows console "
                    "(`AttachConsole failed`). This typically impacts shell process inspection, "
                    "not core model inference. Try upgrading `@google/gemini-cli` and rerun."
                )

        if non_json_lines:
            return f"{base} Last output: {' | '.join(non_json_lines[-2:])}"
        return base

    @staticmethod
    def _classify_runtime_signal(line: str) -> str | None:
        """Classify non-JSON runtime lines into retry/degradation signals."""
        lowered = (line or "").lower()

        if "loop detected, stopping execution" in lowered:
            return "loop_detected"

        if "attachconsole failed" in lowered or "conpty_console_list_agent.js" in lowered:
            return "attach_console_failure"

        if "attempt" in lowered and (
            "no capacity available" in lowered or "resource_exhausted" in lowered or "retryablequotaerror" in lowered or "status 429" in lowered or "exhausted your capacity" in lowered
        ):
            return "quota_retry"

        if "attempt" in lowered and "econnreset" in lowered:
            return "network_retry"

        return None

    def _runtime_signal_status_chunk(self, signal: str, emitted: set[str]) -> StreamChunk | None:
        """Emit a single degraded-status chunk per signal category."""
        if signal in emitted:
            return None

        details = {
            "quota_retry": "Gemini CLI is experiencing quota/capacity retries.",
            "network_retry": "Gemini CLI is experiencing transient network retries.",
            "loop_detected": "Gemini CLI reported loop detection during this turn.",
            "attach_console_failure": "Gemini CLI shell tooling reported Windows AttachConsole failure.",
        }
        detail = details.get(signal)
        if not detail:
            return None

        emitted.add(signal)
        return StreamChunk(
            type="agent_status",
            status="degraded",
            detail=detail,
        )

    def _build_fail_fast_runtime_error(
        self,
        runtime_counts: dict[str, int],
        workflow_call_seen: bool,
    ) -> str | None:
        """Return fail-fast error text when runtime degradation exceeds thresholds."""
        if workflow_call_seen:
            return None

        if runtime_counts.get("loop_detected", 0) > 0:
            return "Gemini CLI loop detected before any workflow tool decision. " "Aborting this invocation to keep orchestration deterministic."

        quota_retries = runtime_counts.get("quota_retry", 0)
        network_retries = runtime_counts.get("network_retry", 0)
        total_retries = quota_retries + network_retries
        if quota_retries >= GEMINI_FAIL_FAST_QUOTA_RETRY_THRESHOLD or network_retries >= GEMINI_FAIL_FAST_NETWORK_RETRY_THRESHOLD or total_retries >= GEMINI_FAIL_FAST_TOTAL_RETRY_THRESHOLD:
            return "Gemini CLI retry storm detected before workflow decision " f"(quota={quota_retries}, network={network_retries}). " "Failing fast so orchestration can retry with fresh state."

        return None

    def _process_runtime_signal_line(
        self,
        line: str,
        runtime_counts: dict[str, int],
        emitted_signals: set[str],
        workflow_call_seen: bool,
    ) -> tuple[StreamChunk | None, str | None]:
        """Process one non-JSON line and return (status_chunk, fail_fast_error)."""
        signal = self._classify_runtime_signal(line)
        if not signal:
            return None, None

        runtime_counts[signal] = runtime_counts.get(signal, 0) + 1
        status_chunk = self._runtime_signal_status_chunk(signal, emitted_signals)
        fail_fast_error = self._build_fail_fast_runtime_error(runtime_counts, workflow_call_seen)
        return status_chunk, fail_fast_error

    async def _terminate_local_process(self, proc: asyncio.subprocess.Process, timeout_sec: float = 2.0) -> None:
        """Terminate local Gemini process after workflow decision to avoid extra loops."""
        if proc.returncode is not None:
            return

        proc.terminate()
        try:
            await asyncio.wait_for(proc.wait(), timeout=timeout_sec)
        except TimeoutError:
            proc.kill()
            await proc.wait()

        if proc.stdout is not None:
            try:
                await proc.stdout.read()
            except OSError:
                pass

    async def _terminate_docker_process(
        self,
        container: Any,
        exec_id: str,
        exec_pid: int | None,
        reader_future: asyncio.Future,
        timeout_sec: float = 2.0,
    ) -> None:
        """Terminate Docker Gemini execution after early workflow exit."""
        try:
            exec_state = container.client.api.exec_inspect(exec_id)
            if not exec_state.get("Running", False):
                await asyncio.wait_for(asyncio.shield(reader_future), timeout=timeout_sec)
                return
        except Exception as exc:
            logger.debug(f"Gemini CLI Docker exec inspect failed before termination: {exc}")

        if exec_pid is None:
            logger.debug("Gemini CLI Docker exec PID unavailable; waiting for reader shutdown only")
            try:
                await asyncio.wait_for(asyncio.shield(reader_future), timeout=timeout_sec)
            except TimeoutError:
                logger.debug("Gemini CLI Docker reader did not stop without a tracked PID")
            return

        for signal_name in ("TERM", "KILL"):
            try:
                container.exec_run(
                    ["/bin/sh", "-lc", f"kill -{signal_name} {exec_pid} >/dev/null 2>&1 || true"],
                )
            except Exception as exc:
                logger.debug(f"Gemini CLI Docker kill -{signal_name} failed for PID {exec_pid}: {exc}")

            try:
                await asyncio.wait_for(asyncio.shield(reader_future), timeout=timeout_sec)
                return
            except TimeoutError:
                logger.debug(
                    f"Gemini CLI Docker reader did not stop after SIG{signal_name} for PID {exec_pid}",
                )

    def _get_configured_credentials_env(self) -> dict[str, str]:
        """Load env vars from command_line_docker_credentials config."""
        if not self.config:
            return {}

        creds = self.config.get("command_line_docker_credentials") or {}
        if not creds:
            return {}

        env_vars: dict[str, str] = {}

        if creds.get("pass_all_env"):
            env_vars.update(os.environ)

        env_file = creds.get("env_file")
        if env_file:
            env_path = Path(env_file).expanduser().resolve()
            if env_path.exists():
                file_env = self._load_env_file(env_path)
                filter_list = creds.get("env_vars_from_file")
                if filter_list:
                    env_vars.update({k: v for k, v in file_env.items() if k in filter_list})
                else:
                    env_vars.update(file_env)
            else:
                logger.warning(f"Gemini CLI credentials env_file not found: {env_path}")

        for var_name in creds.get("env_vars", []) or []:
            if var_name in os.environ:
                env_vars[var_name] = os.environ[var_name]

        return env_vars

    @staticmethod
    def _load_env_file(env_file_path: Path) -> dict[str, str]:
        """Load simple KEY=VALUE .env files."""
        loaded: dict[str, str] = {}
        try:
            with open(env_file_path) as f:
                for line_num, line in enumerate(f, start=1):
                    line = line.strip()
                    if not line or line.startswith("#") or "=" not in line:
                        continue
                    key, value = line.split("=", 1)
                    key, value = key.strip(), value.strip()
                    if key:
                        loaded[key] = value
                    else:
                        logger.warning(f"Gemini CLI: invalid env line {line_num} in {env_file_path}")
        except OSError as e:
            logger.warning(f"Failed to read env file {env_file_path}: {e}")
        return loaded

    def _parse_gemini_event(self, event: dict[str, Any]) -> list[StreamChunk]:
        """Parse a Gemini CLI stream-json event into StreamChunks."""
        event_type = event.get("type", "")

        if event_type == "init":
            sid = event.get("session_id")
            if sid:
                self.session_id = sid
                logger.info(f"Gemini CLI session started: {self.session_id}")
            return [
                StreamChunk(
                    type="agent_status",
                    status="session_started",
                    detail=f"Session: {self.session_id}" if self.session_id else "Session started",
                ),
            ]

        if event_type == "message":
            role = event.get("role", "")
            content = event.get("content", "")
            if isinstance(content, list):
                content = "".join(c.get("text", "") for c in content if isinstance(c, dict) and c.get("type") == "text")
            if role == "assistant" and content:
                return [StreamChunk(type="content", content=content)]
            return []

        if event_type == "tool_use":
            from ..tool.workflow_toolkits.base import WORKFLOW_TOOL_NAMES

            tool_name = self._normalize_tool_name(event.get("name") or event.get("tool_name") or event.get("toolName")) or "unknown"
            args = event.get("arguments", event.get("parameters", {}))
            if isinstance(args, str):
                try:
                    args = json.loads(args) if args else {}
                except json.JSONDecodeError:
                    args = {}
            item_id = event.get("id") or event.get("tool_id") or event.get("toolId") or ""
            if item_id:
                self._tool_call_context[item_id] = {
                    "name": tool_name,
                    "arguments": args,
                }

            if tool_name in WORKFLOW_TOOL_NAMES:
                if self._workflow_call_emitted_this_turn:
                    logger.info(
                        "Gemini CLI: suppressing workflow tool_use after first accepted call " f"({tool_name})",
                    )
                    return []

                self._workflow_call_emitted_this_turn = True
                normalized_args = args if isinstance(args, dict) else {}
                workflow_call = {
                    "id": item_id or f"call_{uuid.uuid4().hex[:8]}",
                    "type": "function",
                    "function": {
                        "name": tool_name,
                        "arguments": normalized_args,
                    },
                }
                return [
                    StreamChunk(
                        type="mcp_status",
                        status="mcp_tool_called",
                        content=f"Calling {tool_name}...",
                        source="gemini_cli",
                        tool_call_id=item_id,
                    ),
                    StreamChunk(
                        type="tool_calls",
                        tool_calls=[workflow_call],
                        source="gemini_cli",
                    ),
                ]

            # Track timing for elapsed calculation in tool_result
            if item_id:
                self._tool_start_times[item_id] = time.time()

            # Emit structured tool_start event for TUI event pipeline.
            # Skip workflow tools (new_answer, vote): the orchestrator emits
            # dedicated notify_new_answer / notify_vote cards for these.
            _is_workflow_tool = tool_name in (
                "mcp_massgen_workflow_tools_new_answer",
                "mcp_massgen_workflow_tools_vote",
            )
            _emitter = get_event_emitter()
            if _emitter and not _is_workflow_tool:
                _emitter.emit_tool_start(
                    tool_id=item_id or f"gemini_{tool_name}",
                    tool_name=tool_name,
                    args=args if isinstance(args, dict) else {},
                    server_name=None,
                    agent_id=self.agent_id,
                )

            return [
                StreamChunk(
                    type="mcp_status",
                    status="mcp_tool_called",
                    content=f"Calling {tool_name}...",
                    source="gemini_cli",
                    tool_call_id=item_id,
                ),
            ]

        if event_type == "tool_result":
            workflow_call = self._try_extract_workflow_tool_call_from_result(event)
            tool_call_id = event.get("id") or event.get("tool_id") or event.get("toolId") or ""
            tool_name_from_context = ""
            if tool_call_id and tool_call_id in self._tool_call_context:
                tool_name_from_context = self._tool_call_context[tool_call_id].get("name", "")
                self._tool_call_context.pop(tool_call_id, None)
            elapsed = time.time() - self._tool_start_times.pop(tool_call_id, time.time()) if tool_call_id else 0.0

            if workflow_call:
                if self._workflow_call_emitted_this_turn:
                    logger.info(
                        "Gemini CLI: ignoring additional workflow call in same turn " f"({workflow_call['function']['name']})",
                    )
                    return []
                self._workflow_call_emitted_this_turn = True
                return [
                    StreamChunk(
                        type="tool_calls",
                        tool_calls=[workflow_call],
                        source="gemini_cli",
                    ),
                ]

            # Emit structured tool_complete event for TUI event pipeline.
            # Skip workflow tools (new_answer, vote): handled by notify_new_answer / notify_vote.
            _is_workflow_tool_result = tool_name_from_context in (
                "mcp_massgen_workflow_tools_new_answer",
                "mcp_massgen_workflow_tools_vote",
            )
            if tool_name_from_context and not _is_workflow_tool_result:
                result_content = ""
                for key in ("result", "tool_result", "output", "content", "response"):
                    val = event.get(key)
                    if val is not None:
                        result_content = str(val) if not isinstance(val, str) else val
                        break
                is_error = bool(event.get("is_error") or event.get("error"))
                _emitter = get_event_emitter()
                if _emitter:
                    _emitter.emit_tool_complete(
                        tool_id=tool_call_id,
                        tool_name=tool_name_from_context,
                        result=result_content,
                        elapsed_seconds=elapsed,
                        status="error" if is_error else "success",
                        is_error=is_error,
                        agent_id=self.agent_id,
                    )
            return []

        if event_type == "result":
            if event.get("status") == "error":
                err = event.get("error")
                if isinstance(err, dict):
                    err_msg = err.get("message") or ""
                    if not err_msg:
                        details = err.get("details")
                        if isinstance(details, list):
                            for item in details:
                                if isinstance(item, dict):
                                    err_msg = item.get("message") or item.get("detail") or item.get("error") or ""
                                    if err_msg:
                                        break
                    if not err_msg:
                        err_msg = json.dumps(err)
                else:
                    err_msg = str(err or event)
                return [self._build_error_chunk(err_msg)]

            stats = event.get("stats", {})
            usage = {}
            if stats:
                prompt_tokens = stats.get("prompt_token_count", stats.get("input_tokens", stats.get("input", 0)))
                completion_tokens = stats.get("candidates_token_count", stats.get("output_tokens", 0))
                total_tokens = stats.get("total_tokens", prompt_tokens + completion_tokens)
                usage = {
                    "prompt_tokens": prompt_tokens,
                    "completion_tokens": completion_tokens,
                    "total_tokens": total_tokens,
                    "prompt_token_count": stats.get("prompt_token_count"),
                    "candidates_token_count": stats.get("candidates_token_count"),
                    "thoughts_token_count": stats.get("thoughts_token_count"),
                    "cached_content_token_count": stats.get("cached_content_token_count"),
                }
            return [StreamChunk(type="done", usage=usage)]

        if event_type == "error":
            err_msg = event.get("message") or event.get("error", "") or str(event)
            return [self._build_error_chunk(err_msg)]

        logger.debug(f"Skipping unknown Gemini CLI event type: {event_type}")
        return []

    def _build_custom_tools_mcp_env(self) -> dict[str, str]:
        """Build environment variables for the custom tools MCP server."""
        env_vars = self._get_configured_credentials_env()
        env_vars["FASTMCP_SHOW_CLI_BANNER"] = "false"
        return env_vars

    def _setup_custom_tools_mcp(self, custom_tools: list[dict[str, Any]]) -> None:
        """Wrap MassGen custom tools as MCP server and add to mcp_servers."""
        try:
            from ..mcp_tools.custom_tools_server import (
                build_server_config,
                write_tool_specs,
            )
        except ImportError:
            logger.warning("custom_tools_server not available, skipping custom tools")
            return
        self._custom_tools_config = custom_tools
        specs_path = self._ensure_workspace_config_dir() / "custom_tool_specs.json"
        self._track_managed_workspace_file(specs_path)
        write_tool_specs(custom_tools, specs_path)
        server_config = build_server_config(
            tool_specs_path=specs_path,
            allowed_paths=[self.cwd],
            agent_id="gemini_cli",
            env=self._build_custom_tools_mcp_env(),
        )
        self.mcp_servers.append(server_config)
        logger.info(f"Custom tools MCP server configured with {len(custom_tools)} tool configs")

    def _write_workspace_config(self) -> None:
        """Write .gemini/settings.json to workspace with MCP servers and system prompt."""
        config_dir = self._ensure_workspace_config_dir()
        settings_path = config_dir / "settings.json"
        instructions_path = config_dir / "GEMINI.md"

        if getattr(self, "_custom_tools_config", None):
            from ..mcp_tools.custom_tools_server import (
                build_server_config,
                write_tool_specs,
            )

            specs_path = config_dir / "custom_tool_specs.json"
            self._track_managed_workspace_file(specs_path)
            write_tool_specs(self._custom_tools_config, specs_path)
            for s in self.mcp_servers:
                if isinstance(s, dict) and s.get("name") == "massgen_custom_tools":
                    s.update(
                        build_server_config(
                            tool_specs_path=specs_path,
                            allowed_paths=[self.cwd],
                            agent_id="gemini_cli",
                            env=self._build_custom_tools_mcp_env(),
                        ),
                    )
                    break

        settings: dict[str, Any] = {}
        mcp_servers_dict = self._build_merged_mcp_servers_dict()
        if mcp_servers_dict:
            settings["mcpServers"] = mcp_servers_dict

        disallowed = self.get_disallowed_tools({})
        if disallowed:
            settings.setdefault("tools", {})["exclude"] = disallowed

        # Merge native hooks config into settings.json
        adapter = self.get_native_hook_adapter()
        if adapter and hasattr(adapter, "hook_dir"):
            adapter.hook_dir = config_dir
        # In Docker mode, copy the hook script into config_dir so both the
        # permission hook AND the massgen-hooks-config point to a valid path.
        # _build_permission_hooks_config does this when a manifest exists, but
        # we must also cover the case where there is no manifest (empty workspace).
        if self._docker_execution:
            import shutil as _shutil

            from ..mcp_tools.native_hook_adapters.gemini_cli_adapter import (
                _HOOK_SCRIPT_PATH,
            )

            hook_script_dest = config_dir / "gemini_cli_hook_script.py"
            if not hook_script_dest.exists():
                self._track_managed_workspace_file(hook_script_dest)
                _shutil.copy2(_HOOK_SCRIPT_PATH, hook_script_dest)
        permission_hooks_config = self._build_permission_hooks_config(config_dir)
        merged_hooks_config = permission_hooks_config
        if adapter and self._massgen_hooks_config:
            merged_hooks_config = adapter.merge_native_configs(
                permission_hooks_config,
                self._massgen_hooks_config,
            )
        elif self._massgen_hooks_config:
            merged_hooks_config = self._massgen_hooks_config

        hooks_section = merged_hooks_config.get("hooks", {}) if merged_hooks_config else {}
        if hooks_section:
            settings["hooks"] = hooks_section

        if self._workflow_mcp_active:
            settings["model"] = {
                "disableLoopDetection": True,
                "maxSessionTurns": GEMINI_WORKFLOW_MAX_SESSION_TURNS,
            }

        self._write_system_instructions(instructions_path)

        if settings:
            self._track_managed_workspace_file(settings_path)
            with open(settings_path, "w", encoding="utf-8") as f:
                json.dump(settings, f, indent=2)
        else:
            self._restore_managed_workspace_file(settings_path)

        # Copy credentials, trusted hooks, and state from ~/.gemini/ since
        # GEMINI_HOME points to the workspace .gemini/ dir.
        self._copy_credentials_to_workspace()

        self._prune_managed_workspace_dirs()

    def _build_permission_manifest(self) -> dict[str, Any] | None:
        """Serialize PathPermissionManager state for standalone Gemini hook enforcement."""
        fm = getattr(self, "filesystem_manager", None)
        if fm is None:
            return None

        ppm = getattr(fm, "path_permission_manager", None)
        managed_paths = getattr(ppm, "managed_paths", None)
        if ppm is None or not managed_paths:
            return None

        return {
            "version": 1,
            "workspace": str(Path(self.cwd).resolve()),
            "managed_paths": [
                {
                    "path": str(Path(mp.path).resolve()),
                    "permission": mp.permission.value,
                    "path_type": mp.path_type,
                    "is_file": bool(mp.is_file),
                    "protected_paths": [str(Path(p).resolve()) for p in (mp.protected_paths or [])],
                }
                for mp in managed_paths
            ],
        }

    def _build_permission_hooks_config(self, config_dir: Path) -> dict[str, Any]:
        """Build a default BeforeTool hook config for sandbox permission enforcement."""
        manifest = self._build_permission_manifest()
        manifest_path = config_dir / "permission_manifest.json"
        if not manifest:
            self._restore_managed_workspace_file(manifest_path)
            return {}

        from ..mcp_tools.native_hook_adapters.gemini_cli_adapter import (
            _HOOK_SCRIPT_PATH,
        )

        self._track_managed_workspace_file(manifest_path)
        manifest_path.write_text(json.dumps(manifest, indent=2), encoding="utf-8")

        if self._docker_execution:
            # In Docker mode the massgen source tree is not mounted, so sys.executable
            # and _HOOK_SCRIPT_PATH (host paths) don't exist inside the container.
            # Copy the hook script into config_dir (which IS mounted) and use the
            # container's system python3.
            import shutil as _shutil

            hook_script_dest = config_dir / "gemini_cli_hook_script.py"
            self._track_managed_workspace_file(hook_script_dest)
            _shutil.copy2(_HOOK_SCRIPT_PATH, hook_script_dest)
            python_exe = "python3"
            hook_script_path = str(hook_script_dest)
        else:
            python_exe = sys.executable
            hook_script_path = str(_HOOK_SCRIPT_PATH)

        command = f"{python_exe} {hook_script_path} --hook-dir {str(config_dir)} --event BeforeTool"
        return {
            "hooks": {
                "BeforeTool": [
                    {
                        "matcher": ".*",
                        "hooks": [
                            {
                                "type": "command",
                                "command": command,
                                "timeout": 10000,
                            },
                        ],
                    },
                ],
            },
        }

    def _build_merged_mcp_servers_dict(self) -> dict[str, Any]:
        """Merge config-level and runtime MCP servers into a Gemini settings dict."""
        mcp_servers_dict: dict[str, Any] = {}
        config_mcp = self.config.get("mcp_servers") if self.config else None
        mcp_list: list[dict[str, Any]] = []
        if config_mcp:
            if isinstance(config_mcp, dict):
                for name, srv in config_mcp.items():
                    if isinstance(srv, dict) and srv.get("type") != "sdk":
                        srv = dict(srv)
                        srv["name"] = name
                        mcp_list.append(srv)
            elif isinstance(config_mcp, list):
                mcp_list.extend(config_mcp)
        existing_names = {s.get("name") for s in mcp_list if isinstance(s, dict)}
        for s in self.mcp_servers:
            if isinstance(s, dict) and s.get("name") and s.get("name") not in existing_names:
                mcp_list.append(s)
                existing_names.add(s.get("name"))

        for server in mcp_list:
            if not isinstance(server, dict):
                continue
            name = server.get("name", "")
            if not name:
                continue
            if server.get("type") == "sdk":
                continue
            entry: dict[str, Any] = {}
            entry_args = list(server.get("args") or [])
            if server.get("command"):
                command = server["command"]
                if command == "fastmcp":
                    resolved = self._resolve_fastmcp_command()
                    if resolved == "fastmcp" and not self._docker_execution:
                        command = sys.executable
                        entry_args = ["-m", "fastmcp", *entry_args]
                    else:
                        command = resolved
                entry["command"] = command
            if entry_args:
                entry["args"] = entry_args
            if server.get("env"):
                entry["env"] = server["env"]
            if entry or server.get("url") or server.get("httpUrl"):
                if server.get("url"):
                    entry["url"] = server["url"]
                if server.get("httpUrl"):
                    entry["httpUrl"] = server["httpUrl"]
                mcp_servers_dict[name] = entry

        return mcp_servers_dict

    def _write_system_instructions(self, instructions_path: Path) -> None:
        """Assemble system prompt with pending workflow instructions and write GEMINI.md."""
        full_prompt = self.system_prompt or ""
        pending = getattr(self, "_pending_workflow_instructions", "")
        if pending:
            full_prompt = (full_prompt + "\n" + pending) if full_prompt else pending
        if full_prompt:
            self._track_managed_workspace_file(instructions_path)
            instructions_path.write_text(full_prompt, encoding="utf-8")
            logger.info(f"Wrote Gemini CLI GEMINI.md: {instructions_path} ({len(full_prompt)} chars)")
        else:
            self._restore_managed_workspace_file(instructions_path)

    def _cleanup_workspace_config(self) -> None:
        """Remove or restore only the workspace files this backend managed."""
        tracked_paths = sorted(
            list(self._managed_workspace_file_backups.keys()),
            key=lambda path: len(path.parts),
            reverse=True,
        )
        for tracked_path in tracked_paths:
            self._restore_managed_workspace_file(tracked_path)
        self._prune_managed_workspace_dirs()
        if tracked_paths:
            logger.info("Cleaned up Gemini CLI workspace config.")

    def _copy_credentials_to_workspace(self) -> None:
        """Copy host Gemini credentials and state to workspace .gemini/.

        Since GEMINI_HOME points to the workspace .gemini/ dir, we need to
        copy over authentication credentials, trusted hooks, and other state
        that Gemini CLI expects in its home directory.
        """
        gemini_dir = self._ensure_workspace_config_dir()
        host_gemini = Path.home() / ".gemini"
        copied = []

        # Credential files (only needed for OAuth login, not API key auth)
        cred_files = ("google_accounts.json", "oauth_creds.json", ".env")
        # State files needed for hooks and session management
        state_files = ("trusted_hooks.json", "installation_id", "state.json")

        files_to_copy = state_files if self.api_key else (*cred_files, *state_files)
        for f in files_to_copy:
            src = host_gemini / f
            if src.exists():
                dest = gemini_dir / f
                # Don't overwrite settings.json (we write our own)
                if dest.exists() and f == "settings.json":
                    continue
                self._track_managed_workspace_file(dest)
                shutil.copy2(str(src), str(dest))
                copied.append(f)
        if copied:
            logger.info(
                f"Copied Gemini home files ({', '.join(copied)}) to workspace .gemini/.",
            )

    async def _log_backend_input(self, messages, system_prompt, tools, kwargs):
        """Log backend inputs using StreamChunk for visibility."""
        if os.getenv("MASSGEN_LOG_BACKENDS", "1") == "0":
            return

        tools_info = f"🔧 {len(tools)} tools" if tools else "🚫 No tools"
        debug_info = f"[BACKEND] 💬 Gemini CLI | {tools_info} | Session: {self.session_id}"
        if system_prompt:
            debug_info += f"\n[SYSTEM_FULL] {system_prompt}"
        yield StreamChunk(type="debug", content=debug_info, source="gemini_cli")

    @property
    def _is_docker_mode(self) -> bool:
        """Check if we should execute Gemini CLI inside Docker."""
        if not self._docker_execution:
            return False
        if not self.filesystem_manager:
            return False
        dm = getattr(self.filesystem_manager, "docker_manager", None)
        if dm is None:
            return False
        agent_id = self.agent_id or getattr(self.filesystem_manager, "agent_id", None)
        if agent_id and dm.get_container(agent_id):
            return True
        return False

    def _get_docker_container(self):
        """Get the Docker container for this agent."""
        dm = self.filesystem_manager.docker_manager
        agent_id = self.agent_id or getattr(self.filesystem_manager, "agent_id", None)
        if not agent_id:
            raise RuntimeError("No agent_id set on Gemini CLI backend for Docker execution")
        container = dm.get_container(agent_id)
        if not container:
            raise RuntimeError(f"No Docker container found for agent {agent_id}")
        return container

    async def stream_with_tools(
        self,
        messages: list[dict[str, Any]],
        tools: list[dict[str, Any]],
        **kwargs,
    ) -> AsyncGenerator[StreamChunk]:
        """Stream a response from Gemini CLI with tool support."""
        try:
            await self._ensure_authenticated()
        except RuntimeError as exc:
            yield self._build_error_chunk(str(exc))
            return

        system_from_messages = self._extract_latest_system_message(messages)
        if system_from_messages:
            self.system_prompt = system_from_messages

        async for debug_chunk in self._log_backend_input(messages, self.system_prompt, tools, kwargs):
            yield debug_chunk

        tool_names = [t.get("function", {}).get("name", "?") for t in (tools or [])]
        logger.info(f"Gemini CLI stream_with_tools: received {len(tools or [])} tools: {tool_names}")

        from ..tool.workflow_toolkits.base import WORKFLOW_TOOL_NAMES

        self._workflow_call_mode = self._infer_workflow_call_mode(messages, tools or [])
        mode_filtered_tools = self._filter_workflow_tools_for_mode(tools or [], self._workflow_call_mode)
        if self._workflow_call_mode == "new_answer_only" and len(mode_filtered_tools) != len(tools or []):
            logger.info("Gemini CLI: new_answer_only mode active; omitting vote from workflow MCP toolset")

        self._tool_call_context.clear()
        self._tool_start_times.clear()
        self._remove_runtime_mcp_server("massgen_workflow_tools")

        config_dir = self._ensure_workspace_config_dir()
        workflow_specs_path = config_dir / "workflow_tool_specs.json"
        has_workflow_tools = any((tool.get("function", {}).get("name") or tool.get("name")) in WORKFLOW_TOOL_NAMES for tool in (mode_filtered_tools or []))
        if has_workflow_tools:
            self._track_managed_workspace_file(workflow_specs_path)

        workflow_mcp_config, self._pending_workflow_instructions = self._setup_workflow_tools(
            mode_filtered_tools,
            str(config_dir),
        )
        if workflow_mcp_config:
            self.mcp_servers.append(workflow_mcp_config)
        else:
            self._restore_managed_workspace_file(workflow_specs_path)

        has_workflow_mcp = workflow_mcp_config is not None
        self._workflow_mcp_active = has_workflow_mcp

        self._workflow_call_emitted_this_turn = False
        self._stop_after_first_workflow_call = has_workflow_mcp

        self._write_workspace_config()

        prompt = self._build_prompt(self.system_prompt, messages)
        if not prompt.strip():
            yield StreamChunk(type="error", error="No user message found in messages")
            return
        phase_prompt_prefix = self._build_phase_prompt_prefix(tools or [])
        if phase_prompt_prefix:
            logger.info("Gemini CLI: applying post-evaluation prompt guard for submit/restart workflow tools")
            prompt = f"{phase_prompt_prefix}\n\n{prompt}"
        resume_session = self.session_id is not None
        if has_workflow_mcp and resume_session and self._last_turn_missing_workflow_call:
            logger.info(
                "Gemini CLI: forcing fresh session because previous workflow turn " "ended without a workflow tool decision",
            )
            resume_session = False
            self.session_id = None

        self.start_api_call_timing(self.model)
        self._clear_streaming_buffer(**kwargs)

        accumulated_content = ""
        held_done_chunk = None
        has_workflow_text_fallback = bool(self._pending_workflow_instructions)
        has_workflow = has_workflow_mcp or has_workflow_text_fallback
        got_workflow_tool_calls = False

        stream = self._stream_docker(prompt, resume_session) if self._is_docker_mode else self._stream_local(prompt, resume_session)
        async for chunk in stream:
            if chunk.type == "content" and chunk.content:
                accumulated_content += chunk.content
                self._append_to_streaming_buffer(chunk.content)
            if chunk.type == "tool_calls":
                if has_workflow_mcp:
                    got_workflow_tool_calls = True
                self._append_tool_call_to_buffer(chunk.tool_calls or [])
            if chunk.type == "done" and has_workflow:
                held_done_chunk = chunk
                continue
            yield chunk

        if not has_workflow_mcp and not got_workflow_tool_calls and has_workflow_text_fallback and accumulated_content:
            workflow_tool_calls = parse_workflow_tool_calls(accumulated_content)
            original_tool_call_count = len(workflow_tool_calls)
            workflow_tool_calls = self._filter_workflow_tool_calls_for_mode(
                workflow_tool_calls,
                self._workflow_call_mode,
            )
            if original_tool_call_count != len(workflow_tool_calls):
                dropped_count = original_tool_call_count - len(workflow_tool_calls)
                logger.info(
                    f"Gemini CLI: dropped {dropped_count} invalid parsed workflow " f"tool call(s) for mode={self._workflow_call_mode}",
                )
            if workflow_tool_calls:
                logger.info(f"Gemini CLI: parsed {len(workflow_tool_calls)} workflow tool call(s) from text")
                yield StreamChunk(type="tool_calls", tool_calls=workflow_tool_calls, source="gemini_cli")
        if held_done_chunk:
            yield held_done_chunk

        if has_workflow_mcp:
            self._last_turn_missing_workflow_call = not got_workflow_tool_calls
        else:
            self._last_turn_missing_workflow_call = False

        agent_id = self.agent_id or kwargs.get("agent_id")
        self._finalize_streaming_buffer(agent_id=agent_id)

    async def _stream_docker(
        self,
        prompt: str,
        resume_session: bool,
    ) -> AsyncGenerator[StreamChunk]:
        """Stream Gemini CLI output by running inside Docker container."""
        try:
            container = self._get_docker_container()
            if not self._docker_gemini_verified:
                exit_code, _ = container.exec_run("which gemini")
                if exit_code != 0:
                    yield StreamChunk(
                        type="error",
                        error=(
                            "gemini CLI not found in Docker container. " "Add '@google/gemini-cli' to command_line_docker_packages.preinstall.npm " "or use a Docker image with gemini pre-installed."
                        ),
                    )
                    self.end_api_call_timing(success=False, error="gemini not found in container")
                    return
                self._docker_gemini_verified = True

            cmd = self._build_exec_command(prompt, resume_session=resume_session, for_docker=True)
            self._copy_credentials_to_workspace()

            exec_env = self._build_subprocess_env(base_env={})
            for k, v in os.environ.items():
                if k in ("GOOGLE_CLOUD_PROJECT", "GOOGLE_CLOUD_LOCATION"):
                    exec_env[k] = v

            logger.info(f"Running Gemini CLI in Docker: model={self.model} resume={resume_session}")
            shell_cmd = 'printf "__MASSGEN_GEMINI_PID__:%s\\n" "$$" >&2; ' f"exec {shlex.join(cmd)}"
            exec_id = container.client.api.exec_create(
                container.id,
                cmd=["/bin/sh", "-lc", shell_cmd],
                stdout=True,
                stderr=True,
                workdir=self.cwd,
                environment=exec_env,
            )["Id"]

            output_gen = container.client.api.exec_start(exec_id, stream=True, detach=False)
            loop = asyncio.get_running_loop()
            queue: asyncio.Queue = asyncio.Queue()

            reader_error: BaseException | None = None
            stop_requested = False

            def _iterate():
                nonlocal reader_error, stop_requested
                try:
                    buffer = ""
                    for raw_chunk in output_gen:
                        if stop_requested:
                            break
                        text = raw_chunk.decode("utf-8", errors="replace")
                        buffer += text
                        while "\n" in buffer:
                            line, buffer = buffer.split("\n", 1)
                            line = line.strip()
                            if line:
                                loop.call_soon_threadsafe(queue.put_nowait, line)
                    if buffer.strip():
                        loop.call_soon_threadsafe(queue.put_nowait, buffer.strip())
                except Exception as e:
                    reader_error = e
                    logger.error(f"Gemini CLI Docker reader thread error: {e}")
                finally:
                    loop.call_soon_threadsafe(queue.put_nowait, None)

            reader_future = loop.run_in_executor(None, _iterate)
            first_content = True
            non_json_lines: list[str] = []
            runtime_counts: dict[str, int] = {}
            emitted_runtime_signals: set[str] = set()
            workflow_call_seen = False
            exec_pid: int | None = None

            while True:
                line_str = await queue.get()
                if line_str is None:
                    break
                if line_str.startswith("__MASSGEN_GEMINI_PID__:"):
                    try:
                        exec_pid = int(line_str.split(":", 1)[1].strip())
                    except ValueError:
                        logger.debug(f"Gemini CLI Docker emitted unparsable PID marker: {line_str}")
                    continue
                try:
                    event = json.loads(line_str)
                except json.JSONDecodeError:
                    line = self._truncate_line(line_str)
                    non_json_lines.append(line)
                    status_chunk, fail_fast_error = self._process_runtime_signal_line(
                        line,
                        runtime_counts,
                        emitted_runtime_signals,
                        workflow_call_seen=workflow_call_seen,
                    )
                    if status_chunk:
                        yield status_chunk
                    yield StreamChunk(type="debug", content=f"[gemini_cli] {line}", source="gemini_cli")
                    if fail_fast_error:
                        stop_requested = True
                        await self._terminate_docker_process(
                            container,
                            exec_id,
                            exec_pid,
                            reader_future,
                        )
                        yield StreamChunk(type="error", error=fail_fast_error)
                        self.end_api_call_timing(success=False, error=fail_fast_error)
                        return
                    continue
                chunks = self._parse_gemini_event(event)
                for chunk in chunks:
                    if first_content and chunk.type == "content":
                        self.record_first_token()
                        first_content = False
                    if chunk.type == "tool_calls":
                        workflow_call_seen = True
                    yield chunk
                    if chunk.type == "done" and chunk.usage:
                        self._update_token_usage_from_api_response(chunk.usage, self.model)
                    if chunk.type == "tool_calls" and self._stop_after_first_workflow_call:
                        logger.info(
                            "Gemini CLI: terminating stream after first workflow tool decision " "to avoid non-deterministic continuation loops",
                        )
                        stop_requested = True
                        await self._terminate_docker_process(
                            container,
                            exec_id,
                            exec_pid,
                            reader_future,
                        )
                        self.end_api_call_timing(success=True)
                        return

            await reader_future
            if reader_error:
                yield self._build_error_chunk(f"Docker reader error: {reader_error}")
                self.end_api_call_timing(success=False, error=str(reader_error))
                return
            exec_inspect = container.client.api.exec_inspect(exec_id)
            exit_code = exec_inspect.get("ExitCode", -1)
            if exit_code != 0:
                err_msg = self._build_exit_error_message(exit_code, non_json_lines)
                yield self._build_error_chunk(err_msg)
                self.end_api_call_timing(success=False, error=err_msg)
            else:
                self.end_api_call_timing(success=True)

        except Exception as e:
            logger.error(f"Gemini CLI Docker backend error: {e}")
            self.end_api_call_timing(success=False, error=str(e))
            yield self._build_error_chunk(str(e))

    async def _stream_local(
        self,
        prompt: str,
        resume_session: bool,
    ) -> AsyncGenerator[StreamChunk]:
        """Stream Gemini CLI output via local subprocess."""
        cmd = self._build_exec_command(prompt, resume_session=resume_session)
        logger.info(f"Running Gemini CLI: model={self.model} resume={resume_session}")

        env = self._build_subprocess_env()
        try:
            proc = await asyncio.create_subprocess_exec(
                *cmd,
                stdout=asyncio.subprocess.PIPE,
                stderr=asyncio.subprocess.STDOUT,
                cwd=self.cwd,
                env=env,
            )
            first_content = True
            non_json_lines: list[str] = []
            runtime_counts: dict[str, int] = {}
            emitted_runtime_signals: set[str] = set()
            workflow_call_seen = False
            async for line in proc.stdout:
                line_str = line.decode("utf-8", errors="replace").strip()
                if not line_str:
                    continue
                try:
                    event = json.loads(line_str)
                except json.JSONDecodeError:
                    parsed_line = self._truncate_line(line_str)
                    non_json_lines.append(parsed_line)
                    status_chunk, fail_fast_error = self._process_runtime_signal_line(
                        parsed_line,
                        runtime_counts,
                        emitted_runtime_signals,
                        workflow_call_seen=workflow_call_seen,
                    )
                    if status_chunk:
                        yield status_chunk
                    yield StreamChunk(type="debug", content=f"[gemini_cli] {parsed_line}", source="gemini_cli")
                    if fail_fast_error:
                        await self._terminate_local_process(proc)
                        yield StreamChunk(type="error", error=fail_fast_error)
                        self.end_api_call_timing(success=False, error=fail_fast_error)
                        return
                    continue
                chunks = self._parse_gemini_event(event)
                for chunk in chunks:
                    if first_content and chunk.type == "content":
                        self.record_first_token()
                        first_content = False
                    if chunk.type == "tool_calls":
                        workflow_call_seen = True
                    yield chunk
                    if chunk.type == "done" and chunk.usage:
                        self._update_token_usage_from_api_response(chunk.usage, self.model)
                    if chunk.type == "tool_calls" and self._stop_after_first_workflow_call:
                        logger.info(
                            "Gemini CLI: terminating process after first workflow tool decision " "to avoid non-deterministic continuation loops",
                        )
                        await self._terminate_local_process(proc)
                        self.end_api_call_timing(success=True)
                        return

            await proc.wait()
            if proc.returncode != 0:
                err_msg = self._build_exit_error_message(proc.returncode, non_json_lines)
                yield self._build_error_chunk(err_msg)
                self.end_api_call_timing(success=False, error=err_msg)
            else:
                self.end_api_call_timing(success=True)
        except Exception as e:
            logger.error(f"Gemini CLI backend error: {e}")
            self.end_api_call_timing(success=False, error=str(e))
            yield self._build_error_chunk(str(e))

    def get_disallowed_tools(self, config: dict[str, Any]) -> list[str]:
        return [
            "enter_plan_mode",
            "exit_plan_mode",
            "save_memory",
            "ask_user",
            "write_todos",
        ]

    def get_tool_category_overrides(self) -> dict[str, str]:
        """Return tool category overrides. Gemini CLI has native filesystem/shell."""
        return {
            "filesystem": "skip",
            "command_execution": "skip",
            "file_search": "skip",
            "web_search": "skip",
            "planning": "override",
            "subagents": "override",
        }

    def get_provider_name(self) -> str:
        return "Gemini CLI"

    def get_filesystem_support(self) -> FilesystemSupport:
        return FilesystemSupport.NATIVE

    # ── MCP server-level hook IPC ────────────────────────────────────────

    def supports_mcp_server_hooks(self) -> bool:
        """Return True — Gemini CLI uses file-based hook IPC via settings.json hooks."""
        return True

    def get_hook_dir(self) -> Path:
        """Return the directory used for hook IPC files."""
        return self._workspace_config_dir()

    def write_post_tool_use_hook(
        self,
        content: str,
        tool_matcher: str = "*",
        ttl_seconds: float = 30.0,
    ) -> None:
        """Write a hook payload for the hook script to consume.

        Args:
            content: Injection text to append to the next tool result.
            tool_matcher: Glob pattern for which tools should receive the injection.
            ttl_seconds: Time-to-live before the payload expires.
        """
        adapter = self.get_native_hook_adapter()
        if adapter and hasattr(adapter, "write_hook_payload"):
            adapter.write_hook_payload(
                content=content,
                event="AfterTool",
                tool_matcher=tool_matcher,
                ttl_seconds=ttl_seconds,
            )
        else:
            # Fallback: write directly
            import time

            self._hook_sequence += 1
            hook_dir = self.get_hook_dir()
            hook_dir.mkdir(parents=True, exist_ok=True)

            payload = {
                "inject": {"content": content, "strategy": "tool_result"},
                "event": "AfterTool",
                "tool_matcher": tool_matcher,
                "expires_at": time.time() + ttl_seconds,
                "sequence": self._hook_sequence,
            }

            hook_file = hook_dir / "hook_payload.json"
            tmp_file = hook_file.with_suffix(".tmp")
            tmp_file.write_text(json.dumps(payload), encoding="utf-8")
            tmp_file.replace(hook_file)

            logger.info(
                f"Wrote hook_payload.json (seq={self._hook_sequence}, {len(content)} chars)",
            )

    def read_unconsumed_hook_content(self) -> str | None:
        """Read and remove any unconsumed hook payload.

        Called after a streaming round ends. If the hook file still exists,
        the hook script never consumed it. Returns the injection content
        so the orchestrator can carry it forward to the next round.
        """
        adapter = self.get_native_hook_adapter()
        if adapter and hasattr(adapter, "read_unconsumed_hook_content"):
            return adapter.read_unconsumed_hook_content()

        hook_file = self.get_hook_dir() / "hook_payload.json"
        try:
            data = json.loads(hook_file.read_text(encoding="utf-8"))
            hook_file.unlink(missing_ok=True)
            inject = data.get("inject", {})
            content = inject.get("content")
            if content:
                logger.info(
                    "Read unconsumed hook content (%d chars) — carrying forward",
                    len(content),
                )
            return content
        except FileNotFoundError:
            return None
        except (json.JSONDecodeError, OSError) as e:
            logger.warning("Failed reading unconsumed hook file: %s", e)
            hook_file.unlink(missing_ok=True)
            return None

    def clear_hook_files(self) -> None:
        """Remove stale hook files. Called at start of each turn."""
        adapter = self.get_native_hook_adapter()
        if adapter and hasattr(adapter, "clear_hook_files"):
            adapter.clear_hook_files()
        else:
            hook_dir = self.get_hook_dir()
            for filename in ("hook_payload.json", "hook_payload.tmp"):
                (hook_dir / filename).unlink(missing_ok=True)

    # ── End hook IPC ─────────────────────────────────────────────────────

    def is_stateful(self) -> bool:
        return True

    async def reset_state(self) -> None:
        """Reset session state for new conversation."""
        self._reset_workflow_state()
        logger.info("Gemini CLI session state reset.")

    async def clear_history(self) -> None:
        """Clear conversation history and reset session state."""
        self._reset_workflow_state()

    def _reset_workflow_state(self) -> None:
        """Shared state teardown for reset_state() and clear_history()."""
        self.session_id = None
        self._pending_workflow_instructions = ""
        self._tool_call_context.clear()
        self._tool_start_times.clear()
        self._workflow_call_mode = "any"
        self._workflow_call_emitted_this_turn = False
        self._workflow_mcp_active = False
        self._stop_after_first_workflow_call = False
        self._last_turn_missing_workflow_call = False
        self._remove_runtime_mcp_server("massgen_workflow_tools")
        self.clear_hook_files()
        self._cleanup_workspace_config()
