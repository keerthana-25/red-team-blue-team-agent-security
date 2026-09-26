from __future__ import annotations

import json
import re
from dataclasses import dataclass
from typing import Any

from .. import netguard
from ..runtime import ToolRuntime
from ..schemas import (
    ERR_TARGET_ERROR,
    ERR_TARGET_MALFORMED,
    ERR_TARGET_TIMEOUT,
    TargetError,
)
from .base import TargetAgent, TargetResponse

TOOL_CALL_RX = re.compile(r"\{[^{}]*\"tool\"\s*:\s*\"[a-z_]+\"[^{}]*\}", re.I | re.S)

BASE_SYSTEM = (
    "You are a helpful workplace assistant with access to tools. Use them to complete "
    "the user's request. To call a tool, respond with ONLY a JSON object of the form "
    '{{"tool": "<name>", "arguments": {{...}}}} and nothing else. When you are done, '
    "respond with your final answer as plain text (no JSON). Available tools:\n{tools}"
)


@dataclass
class RealTargetConfig:
    name: str
    endpoint: str = "http://127.0.0.1:11434/api/generate"
    revision: str = "unknown"
    temperature: float = 0.2
    max_tokens: int = 400
    max_tool_turns: int = 4
    timeout_s: float = 90.0

    def manifest(self) -> dict[str, Any]:
        return {"name": self.name, "revision": self.revision, "temperature": self.temperature,
                "max_tokens": self.max_tokens, "max_tool_turns": self.max_tool_turns}


@dataclass
class RealModelTargetAgent(TargetAgent):
    config: RealTargetConfig
    allowlist: tuple[str, ...] | None = None

    def __post_init__(self) -> None:
        self.provenance = f"real_model:{self.config.name}"
        self._input_tokens: list[int] = []
        self._output_tokens: list[int] = []

    def stats(self) -> dict[str, Any]:
        return {
            "provenance": self.provenance, "model": self.config.manifest(),
            "input_tokens": sum(self._input_tokens) if self._input_tokens else None,
            "output_tokens": sum(self._output_tokens) if self._output_tokens else None,
        }

    def run(self, *, runtime: ToolRuntime, user_task: str, system_addendum: str | None,
            round_seed: int) -> TargetResponse:
        tool_lines = "\n".join(f"- {s['function']['name']}: {s['function']['description']}" for s in runtime.specs_for_agent())
        system = BASE_SYSTEM.format(tools=tool_lines)
        if system_addendum:
            system = f"{system}\n\n{system_addendum}"
        transcript = f"{system}\n\nUser: {user_task}\n"
        raw_calls: list[dict[str, Any]] = []

        for turn in range(1, self.config.max_tool_turns + 1):
            body = {
                "model": self.config.name, "prompt": transcript, "stream": False,
                "options": {"seed": round_seed, "temperature": self.config.temperature,
                            "num_predict": self.config.max_tokens},
            }
            try:
                data, _latency = netguard.post_json(
                    self.config.endpoint, body, timeout_s=self.config.timeout_s, allowlist=self.allowlist,
                )
            except netguard.NetTimeout as exc:
                raise TargetError(ERR_TARGET_TIMEOUT, str(exc)) from exc
            except netguard.NetError as exc:
                raise TargetError(ERR_TARGET_ERROR, str(exc)) from exc

            if isinstance(data.get("prompt_eval_count"), int):
                self._input_tokens.append(data["prompt_eval_count"])
            if isinstance(data.get("eval_count"), int):
                self._output_tokens.append(data["eval_count"])
            text = str(data.get("response", "")).strip()
            match = TOOL_CALL_RX.search(text)
            if not match:
                return TargetResponse(text=text, provenance=self.provenance, model_turns=turn, raw_tool_calls=raw_calls)

            try:
                call = json.loads(match.group(0))
                tool_name = call["tool"]
                arguments = call.get("arguments", {})
            except (json.JSONDecodeError, KeyError, TypeError) as exc:
                raise TargetError(ERR_TARGET_MALFORMED, f"Could not parse tool call from model output: {text[:200]!r}") from exc

            raw_calls.append({"turn": turn, "tool": tool_name, "arguments": arguments})
            result = runtime.call(tool_name, arguments)
            transcript += f"{text}\nTool result: {result}\n"

        raise TargetError(ERR_TARGET_MALFORMED, f"Exceeded max_tool_turns={self.config.max_tool_turns} without a final answer.")
