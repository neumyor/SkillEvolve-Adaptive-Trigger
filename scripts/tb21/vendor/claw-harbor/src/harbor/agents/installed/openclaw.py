import json
import math
import os
import re
import shlex
import traceback
from pathlib import Path
from typing import Any

from harbor.agents.installed.base import BaseInstalledAgent, CliFlag, EnvVar, ExecInput
from harbor.models.agent.context import AgentContext
from harbor.models.agent.name import AgentName
from harbor.models.trajectories import (
    Agent,
    FinalMetrics,
    Metrics,
    Observation,
    ObservationResult,
    Step,
    ToolCall,
    Trajectory,
)

# Path inside the container where OpenClaw writes session state.
_OPENCLAW_STATE_DIR = "/logs/agent/openclaw-state"

# Gateway mode defaults
_GATEWAY_DEFAULT_PORT = 18789
_GATEWAY_DEFAULT_TOKEN = "harbor-bench-token"

# Upper bound for LiteLLM-inferred max_output_tokens to guard against
# unrealistic values (e.g. 10M) that would break provider APIs.
_MAX_OUTPUT_TOKENS_CAP = 1_048_576

# Inline Node.js script for field-aware deep merge of OpenClaw config.
# Reads JSON from process.argv[1], patch from _HARBOR_PATCH env var.
_MERGE_NODE_SCRIPT = (
    "const fs=require('fs');"
    "const cfg=process.argv[1];"
    "const patch=JSON.parse(process.env._HARBOR_PATCH);"
    "const base=fs.existsSync(cfg)?JSON.parse(fs.readFileSync(cfg,'utf8')):{};"
    # mcp.servers: merge, not replace
    "if(patch.mcp){if(!base.mcp)base.mcp={};"
    "base.mcp.servers=Object.assign({},base.mcp.servers,patch.mcp.servers);}"
    # agents.defaults.model
    "if(patch.agents){if(!base.agents)base.agents={};"
    "if(!base.agents.defaults)base.agents.defaults={};"
    "Object.assign(base.agents.defaults,patch.agents.defaults);}"
    # env: merge keys
    "if(!base.env)base.env={};"
    "Object.assign(base.env,patch.env);"
    # models.providers: merge provider entries field by field so partial
    # patches (e.g. only "models") don't clobber existing baseUrl/apiKey.
    "if(patch.models){if(!base.models)base.models={};"
    "if(!base.models.providers)base.models.providers={};"
    "for(const[n,p]of Object.entries(patch.models.providers)){"
    "if(!base.models.providers[n])base.models.providers[n]={};"
    "Object.assign(base.models.providers[n],p);}}"
    # browser: field-level merge to avoid clobbering unrelated browser settings
    "if(patch.browser){if(!base.browser)base.browser={};"
    "const pb=patch.browser,bb=base.browser;"
    "if(pb.headless!==undefined)bb.headless=pb.headless;"
    "if(pb.noSandbox!==undefined)bb.noSandbox=pb.noSandbox;"
    "if(pb.ssrfPolicy){if(!bb.ssrfPolicy)bb.ssrfPolicy={};"
    "Object.assign(bb.ssrfPolicy,pb.ssrfPolicy);}}"
    "fs.writeFileSync(cfg,JSON.stringify(base,null,2));"
)


class OpenClaw(BaseInstalledAgent):
    """Harbor agent adapter for OpenClaw (v2026.3.11+).

    Runs openclaw in gateway mode by default (--local mode is available via
    OPENCLAW_USE_LOCAL=true but has an inherent race condition on session JSONL
    writes). Supports pre-installed images (ghcr.io/openclaw/openclaw:*) via
    install script skip logic.
    """

    SUPPORTS_ATIF: bool = True

    CLI_FLAGS = [
        CliFlag(
            "thinking",
            cli="--thinking",
            type="enum",
            choices=["off", "minimal", "low", "medium", "high", "xhigh", "adaptive"],
            env_fallback="OPENCLAW_THINKING",
        ),
        CliFlag(
            "timeout",
            cli="--timeout",
            type="int",
            env_fallback="OPENCLAW_TIMEOUT",
        ),
        CliFlag(
            "verbose",
            cli="--verbose",
            type="enum",
            choices=["on", "off"],
            env_fallback="OPENCLAW_VERBOSE",
        ),
    ]
    ENV_VARS = [
        EnvVar(
            "anthropic_api_key",
            env="ANTHROPIC_API_KEY",
            env_fallback="ANTHROPIC_API_KEY",
        ),
        EnvVar("openai_api_key", env="OPENAI_API_KEY", env_fallback="OPENAI_API_KEY"),
        EnvVar("gemini_api_key", env="GEMINI_API_KEY", env_fallback="GEMINI_API_KEY"),
        EnvVar(
            "openclaw_gateway_token",
            env="OPENCLAW_GATEWAY_TOKEN",
            env_fallback="OPENCLAW_GATEWAY_TOKEN",
        ),
        EnvVar(
            "volcano_engine_api_key",
            env="VOLCANO_ENGINE_API_KEY",
            env_fallback="VOLCANO_ENGINE_API_KEY",
        ),
    ]

    def __init__(
        self,
        logs_dir: Path,
        *args,
        agent_timeout_sec: int | float | str | None = None,
        **kwargs,
    ):
        super().__init__(logs_dir, *args, **kwargs)
        self._harbor_agent_timeout_sec = self._parse_timeout_seconds(agent_timeout_sec)

    @staticmethod
    def _parse_timeout_seconds(
        raw_timeout: int | float | str | None,
    ) -> int | None:
        """Parse a timeout value to a positive integer.

        Accepts int, float (whole-number or non-integer), and numeric strings.
        Non-integer floats are rounded up via math.ceil() so the CLI receives
        a whole-second timeout value.
        """

        def _err(msg: str) -> ValueError:
            return ValueError(
                f"Invalid agent_timeout_sec value: '{raw_timeout}'. {msg}"
            )

        if raw_timeout is None:
            return None

        if isinstance(raw_timeout, bool):
            raise _err("Must be a positive number.")

        timeout_value: int
        if isinstance(raw_timeout, int):
            timeout_value = raw_timeout
        elif isinstance(raw_timeout, float):
            if not math.isfinite(raw_timeout):
                raise _err("Must be a finite positive number.")
            timeout_value = math.ceil(raw_timeout)
        elif isinstance(raw_timeout, str):
            normalized = raw_timeout.strip()
            if not normalized:
                raise _err("Must be a positive number.")
            try:
                parsed = float(normalized)
            except ValueError as exc:
                raise _err("Must be a positive number.") from exc
            if not math.isfinite(parsed):
                raise _err("Must be a finite positive number.")
            timeout_value = math.ceil(parsed)
        else:
            raise _err("Must be a positive number.")

        if timeout_value <= 0:
            raise _err("Must be > 0 seconds.")

        return timeout_value

    @staticmethod
    def name() -> str:
        return AgentName.OPENCLAW.value

    def get_version_command(self) -> str | None:
        return "openclaw --version 2>/dev/null || node /app/openclaw.mjs --version 2>/dev/null || true"

    def parse_version(self, stdout: str) -> str:
        match = re.search(r"(\d+\.\d+\.\d+)", stdout.strip())
        return match.group(1) if match else stdout.strip()

    @staticmethod
    def _is_truthy_env_value(value: str) -> bool:
        """Check if an env var string value represents boolean true.

        Accepts case-insensitive "1", "true", or "yes". All other values
        (including empty string, "0", "false", "no") return False.
        """
        return value.lower() in ("1", "true", "yes")

    @property
    def _install_agent_template_path(self) -> Path:
        return Path(__file__).parent / "install-openclaw.sh.j2"

    # Known provider connection configs. maxTokens is resolved dynamically
    # via _resolve_max_tokens (LiteLLM inference → 32k fallback). OpenClaw
    # internally clamps maxTokens to contextWindow, so even large values are safe.
    _PROVIDER_CONFIGS: dict[str, dict[str, Any]] = {
        "volcengine": {
            "baseUrl": "https://ark.cn-beijing.volces.com/api/v3",
            "api": "openai-completions",
            "apiKey": "${VOLCANO_ENGINE_API_KEY}",
        },
        "volcengine-plan": {
            "baseUrl": "https://ark.cn-beijing.volces.com/api/coding/v3",
            "api": "openai-completions",
            "apiKey": "${VOLCANO_ENGINE_API_KEY}",
        },
    }

    def _build_full_config_patch(self) -> dict[str, Any]:
        """Build the complete openclaw.json patch as a single Python dict.

        Consolidates MCP servers, model, env/API keys, provider registration, and
        browser settings into one object so a single node invocation can merge
        everything — no temp files, no concurrent-write races.
        """
        patch: dict[str, Any] = {}

        # MCP servers
        if self.mcp_servers:
            servers: dict[str, Any] = {}
            for server in self.mcp_servers:
                if server.transport == "stdio":
                    servers[server.name] = {
                        "transport": "stdio",
                        "command": server.command,
                        "args": server.args,
                    }
                else:
                    # OpenClaw uses "streamable-http" or "sse" transport names directly
                    servers[server.name] = {
                        "transport": server.transport,
                        "url": server.url,
                    }
            patch["mcp"] = {"servers": servers}

        # Model
        if self.model_name:
            patch["agents"] = {"defaults": {"model": self.model_name}}

        # env section: shellEnv flag + API keys.
        # OpenClaw reads provider API keys from its own config env section, not from
        # process.env directly. shellEnv.enabled=true enables shell-env passthrough for
        # other vars, but the gateway token must be listed explicitly here so the
        # embedded gateway can authenticate browser-tool WebSocket connections.
        env_patch: dict[str, Any] = {"shellEnv": {"enabled": True}}
        for key, value in self._resolved_env_vars.items():
            if value:
                env_patch[key] = value
        for key, value in self._extra_env.items():
            if value:
                env_patch[key] = value
        if "OPENCLAW_GATEWAY_TOKEN" not in env_patch:
            env_patch["OPENCLAW_GATEWAY_TOKEN"] = _GATEWAY_DEFAULT_TOKEN
        patch["env"] = env_patch

        # Browser settings required inside Docker (no display server, no kernel sandbox).
        patch["browser"] = {
            "headless": True,
            "noSandbox": True,
            "ssrfPolicy": {"dangerouslyAllowPrivateNetwork": True},
        }

        # Provider registration: explicit config for known providers whose implicit
        # discovery fails inside containers, and for ad-hoc custom endpoints.
        if self.model_name and "/" in self.model_name:
            provider, model_id = self.model_name.split("/", 1)
            provider_entry = self._build_provider_entry(provider, model_id)
            if provider_entry:
                patch["models"] = {"providers": {provider: provider_entry}}

        return patch

    def _resolve_extra_env(self, key: str) -> str | None:
        """Resolve an env var following Harbor's --ae > os.environ priority.

        Uses ``in`` checks (not truthiness) so empty strings in ``_extra_env``
        are respected and do NOT fall through to ``os.environ``.
        """
        if key in self._extra_env:
            return self._extra_env[key]
        if key in os.environ:
            return os.environ[key]
        return None

    def _resolve_max_tokens(self, provider: str, model_id: str) -> int:
        """Resolve max output tokens using a three-tier hierarchy.

        1. Explicit user configuration via CUSTOM_MAX_TOKENS
           (--ae takes precedence over os.environ).
        2. LiteLLM model-info inference (provider/model-id first, bare model-id fallback).
        3. Safe high default of 32768 (clamped to contextWindow by OpenClaw).
        """
        # Tier 1: explicit user configuration
        custom = self._resolve_extra_env("CUSTOM_MAX_TOKENS")
        if custom is not None:
            if custom.strip():
                try:
                    value = int(custom)
                    if value > 0:
                        return value
                except ValueError:
                    pass
                self.logger.warning(
                    "Invalid CUSTOM_MAX_TOKENS value '%s', using inferred/default.",
                    custom,
                )
            else:
                self.logger.debug(
                    "CUSTOM_MAX_TOKENS is empty string; skipping to Tier 2."
                )

        # Tier 2: LiteLLM inference
        try:
            from litellm.utils import get_model_info
        except ImportError:
            self.logger.warning(
                "litellm not available; using default max_output_tokens=32768"
            )
            return 32768

        for lookup in (f"{provider}/{model_id}", model_id):
            try:
                info = get_model_info(lookup)
                max_output = info.get("max_output_tokens")
                if max_output is not None:
                    try:
                        max_output_int = int(max_output)
                        if max_output_int > 0:
                            if max_output_int > _MAX_OUTPUT_TOKENS_CAP:
                                self.logger.warning(
                                    "LiteLLM max_output_tokens=%d exceeds cap %d; using cap.",
                                    max_output_int,
                                    _MAX_OUTPUT_TOKENS_CAP,
                                )
                                return _MAX_OUTPUT_TOKENS_CAP
                            return max_output_int
                    except (ValueError, TypeError):
                        pass
            except Exception:
                continue

        # Tier 3: safe fallback
        return 32768

    def _build_provider_entry(
        self, provider: str, model_id: str
    ) -> dict[str, Any] | None:
        """Return an openclaw models.providers entry for the given provider/model pair."""
        if provider in self._PROVIDER_CONFIGS:
            entry = dict(self._PROVIDER_CONFIGS[provider])
            entry["models"] = [
                {
                    "id": model_id,
                    "name": model_id,
                    "reasoning": False,
                    "input": ["text"],
                    "contextWindow": 256000,
                    "maxTokens": self._resolve_max_tokens(provider, model_id),
                }
            ]
            return entry

        if provider == "custom":
            # Usage: -m custom/<model-id> --ae CUSTOM_BASE_URL=https://... --ae CUSTOM_API_KEY=sk-...
            #
            # Optional overrides (all have defaults):
            #   --ae CUSTOM_CONTEXT_WINDOW=256000   model context window (default: 128000)
            #   --ae CUSTOM_MAX_TOKENS=8192         max output tokens (overrides inference)
            #   --ae CUSTOM_REASONING=true          enable reasoning mode (default: false)
            #   --ae CUSTOM_API=openai-completions  API type (default: openai-completions)
            custom_base_url = self._resolve_extra_env("CUSTOM_BASE_URL") or ""
            if not custom_base_url:
                raise ValueError(
                    "CUSTOM_BASE_URL must be set via --ae when using the 'custom' provider. "
                    "Example: --ae CUSTOM_BASE_URL=https://api.example.com/v1"
                )
            try:
                context_window = int(
                    self._resolve_extra_env("CUSTOM_CONTEXT_WINDOW") or "128000"
                )
            except ValueError:
                context_window = 128000
            max_tokens = self._resolve_max_tokens(provider, model_id)
            reasoning = self._is_truthy_env_value(
                self._resolve_extra_env("CUSTOM_REASONING") or ""
            )
            api = self._resolve_extra_env("CUSTOM_API") or "openai-completions"
            return {
                "baseUrl": custom_base_url,
                "api": api,
                # ${CUSTOM_API_KEY} is resolved by openclaw's env-substitution at
                # config load time — the value comes from the env section above.
                "apiKey": "${CUSTOM_API_KEY}",
                "models": [
                    {
                        "id": model_id,
                        "name": model_id,
                        "reasoning": reasoning,
                        "input": ["text"],
                        "contextWindow": context_window,
                        "maxTokens": max_tokens,
                    }
                ],
            }

        # openrouter / moonshot with custom endpoint:
        # Reuse CUSTOM_* env vars for base URL, API key, and model config.
        # The provider name determines which OpenClaw wrapper is applied:
        #   openrouter → reasoning: { effort: "<level>" } injection
        #   moonshot   → thinking: { type: "enabled" } injection
        # Without CUSTOM_BASE_URL, return None so OpenClaw uses its default config
        # (the real OpenRouter/Moonshot service).
        if provider in ("openrouter", "moonshot"):
            custom_base_url = self._resolve_extra_env("CUSTOM_BASE_URL") or ""
            max_tokens = self._resolve_max_tokens(provider, model_id)

            if not custom_base_url:
                # No custom endpoint. Only inject a provider entry if the user
                # explicitly set CUSTOM_MAX_TOKENS -- otherwise return None so
                # OpenClaw uses its built-in default config unchanged.
                if self._resolve_extra_env("CUSTOM_MAX_TOKENS") is not None:
                    ctx_raw = self._resolve_extra_env("CUSTOM_CONTEXT_WINDOW")
                    try:
                        context_window = int(ctx_raw) if ctx_raw else 128000
                    except ValueError:
                        context_window = 128000
                    return {
                        "models": [
                            {
                                "id": model_id,
                                "name": model_id,
                                "reasoning": False,
                                "input": ["text"],
                                "contextWindow": context_window,
                                "maxTokens": max_tokens,
                            }
                        ],
                    }
                return None
            try:
                context_window = int(
                    self._resolve_extra_env("CUSTOM_CONTEXT_WINDOW") or "128000"
                )
            except ValueError:
                context_window = 128000
            reasoning = self._is_truthy_env_value(
                self._resolve_extra_env("CUSTOM_REASONING") or ""
            )
            api = self._resolve_extra_env("CUSTOM_API") or "openai-completions"
            return {
                "baseUrl": custom_base_url,
                "api": api,
                "apiKey": "${CUSTOM_API_KEY}",
                "models": [
                    {
                        "id": model_id,
                        "name": model_id,
                        "reasoning": reasoning,
                        "input": ["text"],
                        "contextWindow": context_window,
                        "maxTokens": max_tokens,
                    }
                ],
            }

        return None

    def _build_merge_command(self, patch: dict[str, Any]) -> str:
        """Produce a shell command that deep-merges *patch* into ~/.openclaw/openclaw.json.

        The JSON patch is passed via the _HARBOR_PATCH env var — no temp files are
        written, so concurrent harbor trials in the same container cannot collide.
        """
        escaped_patch = shlex.quote(json.dumps(patch))
        escaped_script = shlex.quote(_MERGE_NODE_SCRIPT)

        return (
            f"_HARBOR_PATCH={escaped_patch} "
            f"node -e {escaped_script} ~/.openclaw/openclaw.json"
        )

    def create_run_agent_commands(self, instruction: str) -> list[ExecInput]:
        escaped_instruction = shlex.quote(instruction)

        env: dict[str, str] = {}

        # Merge declarative env vars (API keys resolved via ENV_VARS + env_fallback)
        env.update(self._resolved_env_vars)

        # Skills directory override
        if self.skills_dir:
            env["OPENCLAW_BUNDLED_SKILLS_DIR"] = self.skills_dir

        # Disable diagnostics/telemetry in benchmark context.
        # OpenClaw reads OPENCLAW_DIAGNOSTICS (not OPENCLAW_DIAGNOSTICS_ENABLED).
        # "false" is one of the accepted off-values (see diagnostic-flags.ts).
        env["OPENCLAW_DIAGNOSTICS"] = "false"

        # Redirect session state to a path under /logs/ so the host can access
        # the session JSONL for ATIF trajectory conversion.
        env["OPENCLAW_STATE_DIR"] = _OPENCLAW_STATE_DIR

        # Set gateway token for embedded gateway (--local mode starts an embedded gateway
        # that requires auth; without this token, all browser tool calls fail with 1008
        # "gateway token missing"). shellEnv.enabled=true causes openclaw to read process
        # env, so injecting here is sufficient. Skip if caller already provided a token.
        if not env.get("OPENCLAW_GATEWAY_TOKEN"):
            env["OPENCLAW_GATEWAY_TOKEN"] = _GATEWAY_DEFAULT_TOKEN

        # Remove empty values
        env = {k: v for k, v in env.items() if v}

        setup_parts = [f"mkdir -p ~/.openclaw /logs/agent {_OPENCLAW_STATE_DIR}"]
        setup_parts.append(self._build_merge_command(self._build_full_config_patch()))
        setup_command = " && ".join(setup_parts)

        cli_flags = self.build_cli_flags()

        def _append_flag(flags: str, flag: str) -> str:
            return (flags + " " + flag).strip() if flags else flag

        # Auto-inject --thinking based on CUSTOM_REASONING when no explicit thinking
        # level was configured (via --ak thinking=X or --ae OPENCLAW_THINKING=X).
        #   CUSTOM_REASONING=true  → --thinking medium (balance depth and token cost)
        #   CUSTOM_REASONING=false → --thinking off
        # Priority: --ak thinking=X (1) > --ae/env OPENCLAW_THINKING (2) > CUSTOM_REASONING auto-inject (3) > OpenClaw default (4).
        custom_reasoning_raw = self._resolve_extra_env("CUSTOM_REASONING") or ""
        custom_reasoning = self._is_truthy_env_value(custom_reasoning_raw)
        thinking_not_set = "thinking" not in self._resolved_flags
        if custom_reasoning and thinking_not_set:
            cli_flags = _append_flag(cli_flags, "--thinking medium")
        elif custom_reasoning_raw and not custom_reasoning and thinking_not_set:
            cli_flags = _append_flag(cli_flags, "--thinking off")

        # Auto-inject --timeout when Harbor computed a timeout and user did not
        # explicitly configure one via --ak timeout=... or --ae OPENCLAW_TIMEOUT=...
        if (
            "timeout" not in self._resolved_flags
            and self._harbor_agent_timeout_sec is not None
        ):
            cli_flags = _append_flag(
                cli_flags, f"--timeout {self._harbor_agent_timeout_sec}"
            )

        extra_flags = (cli_flags + " ") if cli_flags else ""

        # Gateway mode is the default. --local mode has an inherent race condition:
        # the embedded gateway starts concurrently with the agent, causing 1006
        # "abnormal closure" errors on the first browser calls. Gateway mode
        # pre-starts the gateway and polls /ready before launching the agent.
        # Opt out with OPENCLAW_USE_LOCAL=true (e.g. --ae OPENCLAW_USE_LOCAL=true).
        use_local = self._is_truthy_env_value(
            self._resolve_extra_env("OPENCLAW_USE_LOCAL") or ""
        )
        if not use_local:
            return self._create_gateway_run_commands(
                escaped_instruction, extra_flags, env, setup_command
            )

        run_command = (
            f"openclaw agent "
            f"--local "
            f"--json "
            f"--session-id harbor "
            f"{extra_flags}"
            f"--message {escaped_instruction} "
            f"2>&1 | tee /logs/agent/openclaw.txt"
        )

        return [
            ExecInput(command=setup_command, env=env),
            ExecInput(command=run_command, env=env),
        ]

    def _create_gateway_run_commands(
        self,
        escaped_instruction: str,
        extra_flags: str,
        env: dict[str, str],
        setup_command: str,
    ) -> list[ExecInput]:
        """Build ExecInput list for gateway mode.

        Checks if a gateway is already running (pre-built images may start one at
        entrypoint). If already ready, skips start and shutdown. Otherwise starts
        openclaw gateway in background, waits for /ready, then shuts it down after
        the agent completes.
        """
        gateway_script = f"""\
set -euo pipefail

GATEWAY_PORT="${{OPENCLAW_GATEWAY_PORT:-{_GATEWAY_DEFAULT_PORT}}}"
GATEWAY_TOKEN="${{OPENCLAW_GATEWAY_TOKEN:-{_GATEWAY_DEFAULT_TOKEN}}}"
GATEWAY_URL="http://localhost:${{GATEWAY_PORT}}"

# Check if a gateway is already running (pre-built image may start one at entrypoint)
GATEWAY_STARTED=0
if curl -sf "${{GATEWAY_URL}}/ready" 2>/dev/null | grep -q '"ready":true'; then
  : # already running, skip startup and shutdown
else
  # Start gateway in background; --allow-unconfigured skips the requirement
  # for gateway.mode to be set in openclaw.json (Harbor manages config via env vars).
  OPENCLAW_GATEWAY_TOKEN="$GATEWAY_TOKEN" \\
  OPENCLAW_GATEWAY_PORT="$GATEWAY_PORT" \\
  openclaw gateway run --allow-unconfigured > /tmp/openclaw-gw.log 2>&1 &
  GATEWAY_PID=$!
  GATEWAY_STARTED=1

  # Wait for /ready endpoint (max 90s — gateway can take 15-20s on first start)
  for i in $(seq 1 90); do
    if curl -sf "${{GATEWAY_URL}}/ready" | grep -q '"ready":true'; then
      break
    fi
    if ! kill -0 "$GATEWAY_PID" 2>/dev/null; then
      echo "Gateway process died after ${{i}}s. Log:" >&2
      tail -20 /tmp/openclaw-gw.log >&2
      exit 1
    fi
    sleep 1
  done

  if ! curl -sf "${{GATEWAY_URL}}/ready" 2>/dev/null | grep -q '"ready":true'; then
    echo "Gateway did not become ready within 90 seconds. Log:" >&2
    tail -30 /tmp/openclaw-gw.log >&2
    exit 1
  fi
fi

# Run agent via gateway (no --local flag).
# Temporarily disable errexit so agent failure does not skip cleanup;
# PIPESTATUS captures openclaw's exit code before tee can mask it.
set +e
OPENCLAW_GATEWAY_URL="$GATEWAY_URL" \\
OPENCLAW_GATEWAY_TOKEN="$GATEWAY_TOKEN" \\
openclaw agent \\
  --json \\
  --session-id harbor \\
  {extra_flags}--message {escaped_instruction} \\
  2>&1 | tee /logs/agent/openclaw.txt
AGENT_EXIT=${{PIPESTATUS[0]}}
set -e

# Shut down the gateway only if this script started it.
#
# No drain sleep is needed before shutdown: openclaw uses appendFileSync
# (synchronous) for all session JSONL writes, so by the time the agent
# process exits (or is killed by harbor's agent timeout), every completed
# turn is already fully persisted on disk. The gateway process itself does
# not buffer any JSONL writes after the agent exits.
#
# `wait` ensures the gateway flushes its own shutdown cleanly before this
# script exits, which is preferable to a fixed sleep.
if [ "$GATEWAY_STARTED" = "1" ]; then
  kill -TERM "$GATEWAY_PID" 2>/dev/null || true
  wait "$GATEWAY_PID" 2>/dev/null || true
fi

exit "$AGENT_EXIT"
"""
        return [
            ExecInput(command=setup_command, env=env),
            ExecInput(command=gateway_script, env=env),
        ]

    # ------------------------------------------------------------------
    # ATIF trajectory conversion
    # ------------------------------------------------------------------

    def _find_session_jsonl(self) -> Path | None:
        """Locate the OpenClaw session JSONL file under the redirected state dir.

        OpenClaw writes session logs to:
          <state_dir>/agents/main/sessions/<sessionId>.jsonl
        """
        sessions_dir = self.logs_dir / "openclaw-state" / "agents" / "main" / "sessions"
        if not sessions_dir.is_dir():
            return None
        jsonl_files = sorted(
            sessions_dir.glob("*.jsonl"), key=lambda p: p.stat().st_mtime
        )
        if not jsonl_files:
            return None
        # Use the most recently modified session file
        return jsonl_files[-1]

    @staticmethod
    def _parse_session_jsonl(path: Path) -> list[dict[str, Any]]:
        """Read a session JSONL file and return parsed entries."""
        entries: list[dict[str, Any]] = []
        for line in path.read_text(encoding="utf-8").splitlines():
            stripped = line.strip()
            if not stripped:
                continue
            try:
                entries.append(json.loads(stripped))
            except json.JSONDecodeError as exc:
                print(f"Skipping malformed JSONL line in {path}: {exc}")
        return entries

    @staticmethod
    def _build_metrics_from_usage(usage: dict[str, Any] | None) -> Metrics | None:
        """Build an ATIF Metrics from an OpenClaw usage dict."""
        if not isinstance(usage, dict):
            return None
        input_tokens = usage.get("input", 0) or 0
        output_tokens = usage.get("output", 0) or 0
        cache_read = usage.get("cacheRead", 0) or 0
        cache_write = usage.get("cacheWrite", 0) or 0
        cached = cache_read + cache_write
        return Metrics(
            prompt_tokens=input_tokens + cached,
            completion_tokens=output_tokens,
            cached_tokens=cached,
        )

    def _convert_session_to_trajectory(
        self, entries: list[dict[str, Any]]
    ) -> Trajectory | None:
        """Convert parsed OpenClaw session JSONL entries into an ATIF Trajectory.

        Session JSONL format:
        - Line 0: {"type": "session", "version": 3, "id": "...", "timestamp": "...", ...}
        - Line 1+: {"type": "message", "id": "...", "message": {"role": "user|assistant|toolResult", "content": ..., "usage": {...}, ...}}
        """
        if not entries:
            return None

        # Extract session metadata from the header entry
        session_id = "unknown"
        session_timestamp: str | None = None
        for entry in entries:
            if entry.get("type") == "session":
                session_id = entry.get("id", session_id)
                session_timestamp = entry.get("timestamp")
                break

        steps: list[Step] = []
        step_id = 0

        for entry in entries:
            if entry.get("type") != "message":
                continue

            msg = entry.get("message")
            if not isinstance(msg, dict):
                continue

            role = msg.get("role", "")
            content = msg.get("content")
            timestamp = entry.get("timestamp")
            usage = msg.get("usage")

            if role == "user":
                step_id += 1
                text = self._extract_text(content)
                steps.append(
                    Step(
                        step_id=step_id,
                        timestamp=timestamp,
                        source="user",
                        message=text or "",
                    )
                )

            elif role == "assistant":
                step_id += 1
                text, reasoning, tool_calls = self._extract_assistant_content(content)
                metrics = self._build_metrics_from_usage(usage)

                step = Step(
                    step_id=step_id,
                    timestamp=timestamp,
                    source="agent",
                    message=text or "",
                    reasoning_content=reasoning,
                    tool_calls=tool_calls or None,
                    metrics=metrics,
                    model_name=self.model_name,
                )
                steps.append(step)

            elif role == "toolResult":
                # Merge tool results as observation into the preceding agent step
                if steps and steps[-1].source == "agent":
                    prev = steps[-1]
                    result_content = self._extract_text(content)
                    # Match by toolCallId from the toolResult message
                    tool_call_id = msg.get("toolCallId") or msg.get("toolUseId")
                    source_call_id: str | None = None
                    if tool_call_id and prev.tool_calls:
                        for tc in prev.tool_calls:
                            if tc.tool_call_id == tool_call_id:
                                source_call_id = tc.tool_call_id
                                break
                    elif prev.tool_calls:
                        # Fallback: no toolCallId available, use last tool call
                        source_call_id = prev.tool_calls[-1].tool_call_id

                    obs_result = ObservationResult(
                        source_call_id=source_call_id,
                        content=result_content,
                    )
                    if prev.observation is None:
                        prev.observation = Observation(results=[obs_result])
                    else:
                        prev.observation.results.append(obs_result)

        if not steps:
            return None

        # Aggregate final metrics
        prompt_values = [
            s.metrics.prompt_tokens
            for s in steps
            if s.metrics and s.metrics.prompt_tokens is not None
        ]
        completion_values = [
            s.metrics.completion_tokens
            for s in steps
            if s.metrics and s.metrics.completion_tokens is not None
        ]
        cached_values = [
            s.metrics.cached_tokens
            for s in steps
            if s.metrics and s.metrics.cached_tokens is not None
        ]

        final_metrics = FinalMetrics(
            total_prompt_tokens=sum(prompt_values) if prompt_values else None,
            total_completion_tokens=sum(completion_values)
            if completion_values
            else None,
            total_cached_tokens=sum(cached_values) if cached_values else None,
            total_steps=len(steps),
        )

        return Trajectory(
            schema_version="ATIF-v1.2",
            session_id=session_id,
            agent=Agent(
                name=AgentName.OPENCLAW.value,
                version=self._version or "unknown",
                model_name=self.model_name,
            ),
            steps=steps,
            final_metrics=final_metrics,
            extra={"session_timestamp": session_timestamp}
            if session_timestamp
            else None,
        )

    @staticmethod
    def _extract_text(content: Any) -> str:
        """Extract plain text from OpenClaw message content."""
        if isinstance(content, str):
            return content
        if isinstance(content, list):
            parts: list[str] = []
            for block in content:
                if isinstance(block, dict):
                    if block.get("type") == "text":
                        parts.append(block.get("text", ""))
                elif isinstance(block, str):
                    parts.append(block)
            return "\n\n".join(p for p in parts if p)
        if content is not None:
            return json.dumps(content, ensure_ascii=False)
        return ""

    @staticmethod
    def _extract_assistant_content(
        content: Any,
    ) -> tuple[str, str | None, list[ToolCall] | None]:
        """Extract text, reasoning, and tool calls from assistant message content."""
        if isinstance(content, str):
            return content, None, None
        if not isinstance(content, list):
            text = (
                json.dumps(content, ensure_ascii=False) if content is not None else ""
            )
            return text, None, None

        text_parts: list[str] = []
        reasoning_parts: list[str] = []
        tool_calls: list[ToolCall] = []

        for block in content:
            if not isinstance(block, dict):
                text_parts.append(str(block))
                continue

            block_type = block.get("type", "")

            if block_type == "text":
                text_parts.append(block.get("text", ""))
            elif block_type in ("thinking", "reasoning"):
                thinking_text = block.get("text") or block.get("thinking") or ""
                if thinking_text:
                    reasoning_parts.append(thinking_text)
            elif block_type in ("tool_use", "toolUse", "toolCall", "functionCall"):
                call_id = block.get("id") or block.get("tool_use_id")
                if not call_id:
                    continue  # Skip tool call blocks without an id
                tool_calls.append(
                    ToolCall(
                        tool_call_id=call_id,
                        function_name=block.get("name", ""),
                        arguments=block.get("input") or block.get("arguments") or {},
                    )
                )
            else:
                text_val = block.get("text")
                if isinstance(text_val, str):
                    text_parts.append(text_val)

        text = "\n\n".join(p.strip() for p in text_parts if p and p.strip())
        reasoning = "\n\n".join(p.strip() for p in reasoning_parts if p and p.strip())

        return text, (reasoning or None), (tool_calls or None)

    def _try_build_trajectory(self) -> Trajectory | None:
        """Attempt to build an ATIF trajectory from the session JSONL."""
        session_path = self._find_session_jsonl()
        if not session_path:
            return None
        try:
            entries = self._parse_session_jsonl(session_path)
            return self._convert_session_to_trajectory(entries)
        except Exception as exc:
            print(f"Failed to convert OpenClaw session to trajectory: {exc}")
            traceback.print_exc()
            return None

    # ------------------------------------------------------------------
    # Post-run context population
    # ------------------------------------------------------------------

    def populate_context_post_run(self, context: AgentContext) -> None:
        """Populate token usage from ATIF trajectory, falling back to --json stdout."""
        # 1. Try ATIF trajectory conversion
        trajectory = self._try_build_trajectory()
        if trajectory:
            trajectory_path = self.logs_dir / "trajectory.json"
            try:
                trajectory_path.write_text(
                    json.dumps(trajectory.to_json_dict(), indent=2, ensure_ascii=False),
                    encoding="utf-8",
                )
                print(f"Wrote OpenClaw trajectory to {trajectory_path}")
            except OSError as exc:
                print(f"Failed to write trajectory file {trajectory_path}: {exc}")

            if trajectory.final_metrics:
                metrics = trajectory.final_metrics
                context.n_input_tokens = metrics.total_prompt_tokens or 0
                context.n_output_tokens = metrics.total_completion_tokens or 0
                context.n_cache_tokens = metrics.total_cached_tokens or 0
            return

        # 2. Fallback: parse --json stdout output
        self._parse_json_stdout_usage(context)

    def _parse_json_stdout_usage(self, context: AgentContext) -> None:
        """Parse token usage from openclaw --json stdout output (fallback path)."""
        log_path = self.logs_dir / "openclaw.txt"

        if not log_path.exists():
            print(f"OpenClaw log not found at {log_path}")
            return

        try:
            raw = log_path.read_text(encoding="utf-8")
        except OSError as exc:
            print(f"Failed to read OpenClaw log: {exc}")
            return

        # --json emits pretty-printed multi-line JSON; find the last top-level
        # object by scanning backwards for a line starting with '{'
        lines = raw.splitlines()
        for i in range(len(lines) - 1, -1, -1):
            if lines[i].strip().startswith("{"):
                try:
                    parsed = json.loads("\n".join(lines[i:]))
                    usage = parsed.get("meta", {}).get("agentMeta", {}).get("usage")
                    if isinstance(usage, dict):
                        cache_read = usage.get("cacheRead", 0) or 0
                        cache_write = usage.get("cacheWrite", 0) or 0
                        cached = cache_read + cache_write
                        # n_input_tokens follows the same semantic as
                        # Metrics.prompt_tokens: total input including cache
                        # hits and writes (matches the ATIF path in
                        # _build_metrics_from_usage).
                        context.n_input_tokens = (usage.get("input", 0) or 0) + cached
                        context.n_output_tokens = usage.get("output", 0) or 0
                        context.n_cache_tokens = cached
                    break
                except json.JSONDecodeError:
                    continue
