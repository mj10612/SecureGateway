"""Loopback subscription proxy. CLI-owned OAuth is forwarded, never loaded from disk.

Only inference endpoints are proxied. Unknown/binary payloads fail closed. SSE is
buffered so aliases split across events can be restored before local execution.
"""

from __future__ import annotations

from contextlib import ExitStack
from copy import deepcopy
from hashlib import sha256
from http.server import BaseHTTPRequestHandler, ThreadingHTTPServer
import json
import math
import http.client
from pathlib import Path
import re
import secrets
import socket
import sqlite3
import time
from threading import Condition, RLock
from typing import Any
import urllib.error
import urllib.request
import urllib.parse

from secure_mcp.engine.masking_engine import MaskingEngine, NumericLiteralConflict
from secure_mcp.engine.strategies import mapping_key
from secure_mcp.encrypted_session import (
    SessionExpiredError,
    SnapshotEncryption,
    load_session,
    save_session,
)
from secure_mcp.hooks import _atomic_json
from secure_mcp.gateway_validation import validate_request
from secure_mcp.gateway_validation import validate_cache_control
from secure_mcp.engine.grammar_en import CLOSED_CLASS_WORDS
from secure_mcp.gateway_source import looks_like_source
from secure_mcp.gateway_catalog import fetch_catalog
from secure_mcp.gateway_audit import AuditStore, anonymous_ref
from secure_mcp.gateway_admin import handle_admin
from secure_mcp.models import MaskMode, SurrogateStrategy, TokenMapping, TokenType
from secure_mcp.session import PrivacySession

LIMIT = 16 * 1024 * 1024
JSON_SCHEMA_DIALECTS = {
    "https://json-schema.org/draft/2020-12/schema",
    "https://json-schema.org/draft/2019-09/schema",
    "https://json-schema.org/schema",
    "https://json-schema.org/schema#",
    "http://json-schema.org/schema#",
    "http://json-schema.org/draft-07/schema#",
    "http://json-schema.org/draft-06/schema#",
    "http://json-schema.org/draft-04/schema#",
    "http://json-schema.org/draft-03/schema#",
    "https://spec.openapis.org/oas/3.1/dialect/base",
}
EXEC_GRAMMAR = r"""
start: pragma_source | plain_source
pragma_source: PRAGMA_LINE NEWLINE SOURCE
plain_source: SOURCE

PRAGMA_LINE: /[ \t]*\/\/ @exec:[^\r\n]*/
NEWLINE: /\r?\n/
SOURCE: /[\s\S]+/
"""
# Pinned OpenAI public apply_patch grammar, with/without environment selection.
PATCH_GRAMMAR_HASHES = {
    "50b06e74592ca36baf0a0804a36d76aef1847b251c7b5b5bfd9bc81ec7794023",
    "1f1bb6528b7ab190a5542bc710053077515f5f800cd58e77f141820566ca4f20",
}
TASK_WORDS = {
    "review",
    "inspect",
    "analyze",
    "explain",
    "fix",
    "implement",
    "read",
    "search",
    "find",
    "summarize",
    "compare",
    "refactor",
    "test",
    "check",
    "show",
    "repeat",
    "reply",
    "exactly",
    "identifier",
    "function",
    "code",
    "file",
    "directory",
    "bug",
    "security",
    "syntax",
    "error",
    "issue",
    "result",
    "please",
    "검토",
    "검토해줘",
    "봐줘",
    "설명",
    "설명해줘",
    "고쳐줘",
    "함수",
    "코드",
    "파일",
    "보안",
    "오류",
    "수정",
    "분석",
    "분석해줘",
    "읽어줘",
    "보여줘",
    "반환",
    "값",
    "그대로",
}
PRIVACY_INSTRUCTION = (
    "The following context was masked locally. Names and values beginning private_symbol_ "
    "and numeric aliases are opaque. Keep every supplied alias exactly unchanged in "
    "answers and tool arguments; a local host restores them. Never invent aliases or "
    "guess originals. Use public names for newly introduced identifiers. State when "
    "hidden literal values prevent analysis.\n"
)
PUBLIC_CLAUDE_IDENTITY = "You are Claude Code, Anthropic's official CLI for Claude."
PUBLIC_CLAUDE_IDENTITIES = (
    PUBLIC_CLAUDE_IDENTITY,
    "You are a Claude agent, built on Anthropic's Claude Agent SDK.",
)
CLAUDE_ATTRIBUTION_PREFIX = "x-anthropic-billing-header:"
# This positional protocol block is consumed by Anthropic before model inference.
# Pin its observed fields rather than passing arbitrary system text through.
CLAUDE_ATTRIBUTION = re.compile(
    r"x-anthropic-billing-header: cc_version=[0-9]{1,6}\.[0-9]{1,6}\.[0-9]{1,6}"
    r"(?:\.[0-9a-f]{3})?; cc_entrypoint=(?:cli|sdk-cli);"
    r"(?: cch=[0-9a-f]{6,64};)?[ \t]*"
)
TOOL_DESCRIPTIONS = {
    "Read": "Read a local file using file_path.",
    "Bash": "Run a local shell command using command.",
    "PowerShell": "Run a local PowerShell command.",
    "exec_command": "Run a local shell command using cmd; return output and session_id.",
    "write_stdin": "Send chars to a running session_id, or poll for output.",
    "Write": "Write content into a local file using file_path.",
    "Edit": "Replace old_string with new_string in file_path.",
    "Grep": "Search local file contents for pattern.",
    "Glob": "Find local files matching pattern.",
    "apply_patch": "Apply a patch to local files using the supplied patch grammar.",
}
UPSTREAMS = {
    "claude": "https://api.anthropic.com",
    "codex": "https://chatgpt.com/backend-api/codex",
}
# Explicit API-key modes. These are never enabled implicitly and never fall
# back to a subscription token; see docs/COMPATIBILITY.md and GATEWAY.md.
API_UPSTREAMS = {
    "xai": "https://api.x.ai",
}
API_AUTH_PREFIXES = {
    "xai": "Bearer xai-",
}
PROTOCOL = {
    "type",
    "role",
    "id",
    "call_id",
    "tool_use_id",
    "tool_call_id",
    "model",
    "status",
    "stop_reason",
    "object",
    "effort",
    "verbosity",
    "syntax",
}
# JSON Schema keywords whose direct child names are aliased by walk().
# A local `$ref` pointer keeps array indexes and all other keywords intact so
# the masked reference still resolves inside the masked schema.
SCHEMA_NAME_KEYWORDS = {
    "properties",
    "$defs",
    "definitions",
    "dependentSchemas",
    "dependentRequired",
    "dependencies",
}
# JSON data positions where protocol/schema exceptions must not apply:
# enum/const/default/examples hold arbitrary data, not envelope metadata.
DATA_KEYWORDS = {"enum", "const", "default", "examples"}
SCHEMA_TYPES = {"object", "string", "number", "integer", "array", "boolean", "null"}
TOOL_NAMES = {
    "Bash",
    "PowerShell",
    "Read",
    "Edit",
    "Write",
    "Grep",
    "Glob",
    "MultiEdit",
    "TodoWrite",
    "Task",
    "Agent",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "exec_command",
    "write_stdin",
    "apply_patch",
    "update_plan",
    "request_user_input",
    "functions",
    "exec",
    "parallel",
    "list_mcp_resources",
    "list_mcp_resource_templates",
    "read_mcp_resource",
    "view_image",
    "spawn_agent",
    "send_input",
    "wait",
    "close_agent",
}
TOP_FIELDS = {
    "model",
    "messages",
    "system",
    "input",
    "instructions",
    "tools",
    "tool_choice",
    "parallel_tool_calls",
    "reasoning",
    "stream",
    "store",
    "max_output_tokens",
    "max_tokens",
    "include",
    "metadata",
    "text",
    "prompt_cache_key",
    "safety_identifier",
    "service_tier",
    "temperature",
    "top_p",
    "top_k",
    "truncation",
    "background",
    "stop_sequences",
    "thinking",
    "output_config",
    "context_management",
    "client_metadata",
    "safeguards",
}
BLOCKED_TYPES = {
    "image",
    "document",
    "input_image",
    "input_file",
    "input_audio",
    "computer",
    "computer_20250124",
    "computer_20251124",
}
ARGUMENT_KEYS = {
    "cmd",
    "command",
    "path",
    "file_path",
    "filePath",
    "content",
    "text",
    "old_string",
    "new_string",
    "pattern",
    "query",
    "yield_time_ms",
    "max_output_tokens",
    "session_id",
    "chars",
    "workdir",
    "timeout",
    "description",
    "shell",
    "login",
    "tty",
    "justification",
    "sandbox_permissions",
    "prefix_rule",
    "input",
    "patch",
}


def validate_api_options(payload, dialect):
    """Only public, typed API controls may bypass text masking."""
    controls = {
        "model",
        "stream",
        "store",
        "parallel_tool_calls",
        "max_output_tokens",
        "max_tokens",
        "max_completion_tokens",
        "temperature",
        "top_p",
        "background",
        "truncation",
        "reasoning",
        "include",
        "service_tier",
        "stream_options",
        "metadata",
        "client_metadata",
        "reasoning_effort",
        "prompt_cache_key",
        "safety_identifier",
    }
    content = {
        "input",
        "instructions",
        "messages",
        "tools",
        "tool_choice",
        "text",
        "stop",
        "response_format",
    }
    if set(payload) - controls - content:
        raise ValueError("Unsupported API controls.")
    for key in {
        "stream",
        "store",
        "parallel_tool_calls",
        "background",
    } & payload.keys():
        if not isinstance(payload[key], bool):
            raise ValueError("API boolean controls must be booleans.")
    for key in {
        "max_output_tokens",
        "max_tokens",
        "max_completion_tokens",
    } & payload.keys():
        if type(payload[key]) is not int or payload[key] < 1:
            raise ValueError("API token limits must be positive integers.")
    for key in {"temperature", "top_p"} & payload.keys():
        if type(payload[key]) not in {int, float} or not 0 <= payload[key] <= (
            2 if key == "temperature" else 1
        ):
            raise ValueError("Invalid API sampling control.")
    for key, allowed in {
        "truncation": {"disabled"},
        "service_tier": {"auto", "default", "flex", "priority"},
    }.items():
        if key in payload and (
            not isinstance(payload[key], str) or payload[key] not in allowed
        ):
            raise ValueError("Unsupported API control enum.")
    if "model" in payload and (
        not isinstance(payload["model"], str)
        or not re.fullmatch(r"[A-Za-z0-9_./:-]{1,200}", payload["model"])
    ):
        raise ValueError("Invalid model ID.")
    if "reasoning" in payload:
        reasoning = payload["reasoning"]
        enums = {
            "effort": {"none", "minimal", "low", "medium", "high", "xhigh"},
            "summary": {"auto", "concise", "detailed"},
        }
        if (
            not isinstance(reasoning, dict)
            or set(reasoning) - enums.keys()
            or any(
                not isinstance(value, str) or value not in enums[key]
                for key, value in reasoning.items()
            )
        ):
            raise ValueError("Unsupported reasoning controls.")
    if "include" in payload and (
        not isinstance(payload["include"], list)
        or any(item != "reasoning.encrypted_content" for item in payload["include"])
    ):
        raise ValueError("Unsupported API include fields.")
    if "stop" in payload and not (
        isinstance(payload["stop"], str)
        or isinstance(payload["stop"], list)
        and 1 <= len(payload["stop"]) <= 4
        and all(isinstance(item, str) for item in payload["stop"])
    ):
        raise ValueError("Stop sequences must be text or a list of text.")
    if dialect == "chat_completions" and set(payload) & {
        "input",
        "instructions",
        "text",
        "max_output_tokens",
        "include",
    }:
        raise ValueError("Responses controls are unsupported in Chat Completions.")
    if dialect == "responses" and set(payload) & {
        "messages",
        "stop",
        "max_completion_tokens",
        "max_tokens",
        "stream_options",
        "reasoning_effort",
        "response_format",
    }:
        raise ValueError("Chat controls are unsupported in Responses.")


class SharedEngine(MaskingEngine):
    """One alias for an original in prompts, code, paths and tool results."""

    def __init__(self, mapping_limit=100_000):
        super().__init__()
        self.mapping_limit = mapping_limit

    def _get_or_create_surrogate(
        self,
        original_token,
        token_type,
        generator,
        mapping_store,
        reverse_store,
        code=False,
    ):
        with generator.operation():
            kind = (
                TokenType.NUMBER
                if token_type == TokenType.NUMBER
                else TokenType.IDENTIFIER
            )
            key = mapping_key(original_token, kind, code=True)
            if key in mapping_store:
                if kind == TokenType.NUMBER and mapping_store[key].surrogate == original_token:
                    raise NumericLiteralConflict("Numeric literal conflicts with a preserved number; use a new session.")
                mapping_store[key].occurrence_count += 1
                return mapping_store[key].surrogate
            if len(mapping_store) >= self.mapping_limit:
                raise ValueError(
                    "Mapping limit reached; reset the gateway and start a new conversation."
                )
            while True:
                surrogate = generator.generate(kind, original_token, code=True)
                if kind == TokenType.NUMBER:
                    break
                surrogate = surrogate.replace("smcp_ID_", "private_symbol_", 1)
                if (
                    surrogate != original_token
                    and surrogate not in generator.used_surrogates
                ):
                    generator.used_surrogates.add(surrogate)
                    break
            mapping = TokenMapping(
                original=original_token,
                surrogate=surrogate,
                token_type=kind,
                context="code",
            )
            mapping_store[key] = mapping
            reverse_store[surrogate] = mapping
            return surrogate


class GatewaySession:
    def __init__(self, session=None, mapping_limit=100_000, mask_numbers=False):
        if type(mask_numbers) is not bool:
            raise ValueError("mask_numbers must be a boolean.")
        self.mask_numbers = mask_numbers
        self.session = session or PrivacySession(
            "gateway", strategy=SurrogateStrategy.UNICODE, ttl_seconds=86400
        )
        self.engine = SharedEngine(mapping_limit)
        self.lock = RLock()
        self.opaque: set[str] = set()
        self.active_requests = 0
        self.encryption: SnapshotEncryption | None = None

    def _opaque_key(self, block):
        stable = {
            key: value for key, value in block.items() if key not in {"id", "status"}
        }
        # Native Codex omits an empty content list when replaying reasoning.
        # Retain nonempty content and ciphertext in the provenance digest.
        if stable.get("type") == "reasoning" and stable.get("content") in (None, []):
            stable.pop("content", None)
        return sha256(
            json.dumps(stable, sort_keys=True, ensure_ascii=False).encode()
        ).hexdigest()

    def _mask_prose(self, text: str, preserve_task_words: bool = True) -> str:
        s = self.session
        # Existing source aliases take precedence over prose grammar (e.g. A).
        terms = s.forward_store.originals_in(text)
        terms.update(word for word in re.findall(r"\b[A-Z]\b", text)
                     if not preserve_task_words or word.lower() not in CLOSED_CLASS_WORDS)
        terms.update(re.findall(r"\b([A-Z])(?=\s+(?:함수|변수|식별자|클래스))", text))
        terms.update(re.findall(r"\b(?:function|variable|identifier|class)\s+([A-Z])\b", text))
        return self.engine.mask_text(
            text,
            s.session_id,
            s.generator,
            s.forward_store,
            s.reverse_store,
            mode=MaskMode.CONTENT_WORDS,
            sensitive_terms=terms,
            # Code fragments keep the "no identifier preservation" rule.
            custom_preserve=TASK_WORDS if preserve_task_words else None,
        ).masked_text

    def _mask_source(self, text: str, language: str = "auto") -> str:
        """Lex a source fragment, falling back to text masking for prose.

        Code lexing rejects unterminated literals, which is correct for the
        strict library API. Backtick/fence fragments inside a normal prompt can
        be prose (an apostrophe like ``don't``), so retry that fragment with
        text masking instead of failing the entire request. The fallback still
        masks content words and never forwards the fragment unmasked.
        """
        s = self.session
        try:
            return self.engine.mask_code(
                text,
                s.session_id,
                s.generator,
                s.forward_store,
                s.reverse_store,
                language=language,
                mask_numbers=self.mask_numbers,
            ).masked_text
        except NumericLiteralConflict:
            raise
        except ValueError:
            return self._mask_prose(text, preserve_task_words=False)

    def mask(self, text: str, code: bool = False, language: str = "auto") -> str:
        if code:
            return self._mask_source(text, language)
        if "```" not in text and looks_like_source(text):
            return self.mask(text, code=True)
        # Fenced/inline source is lexed, rather than replaced as an opaque block.
        parts = re.split(
            r"(```[^\n]*\n[\s\S]*?```|`[^`\n]+`|"
            + "|".join(re.escape(identity) for identity in PUBLIC_CLAUDE_IDENTITIES)
            + ")",
            text,
        )
        output = []
        for part in parts:
            if part in PUBLIC_CLAUDE_IDENTITIES:
                output.append(part)
                continue
            if part.startswith("```") and "\n" in part and part.endswith("```"):
                header, body = part.split("\n", 1)
                if header[3:].strip().lower() not in {
                    "python",
                    "py",
                    "javascript",
                    "js",
                    "typescript",
                    "ts",
                    "go",
                    "rust",
                    "rs",
                    "java",
                    "c",
                    "cpp",
                    "c++",
                    "sql",
                    "",
                }:
                    header = "```"
                output.append(
                    header
                    + "\n"
                    + self._mask_source(body[:-3], header[3:].strip() or "auto")
                    + "```"
                )
            elif part.startswith("`") and part.endswith("`") and len(part) > 1:
                output.append("`" + self._mask_source(part[1:-1]) + "`")
            else:
                output.append(self._mask_prose(part))
        return "".join(output)

    def restore(self, text):
        s = self.session
        return self.engine.unmask(
            text, s.session_id, s.reverse_store, s.strategy, strict=True
        ).unmasked_text

    def values(self, value, restore=False, code=False):
        operation = self.restore if restore else lambda text: self.mask(text, code=code)
        if isinstance(value, str):
            return operation(value)
        if isinstance(value, list):
            return [self.values(item, restore, code) for item in value]
        if isinstance(value, dict):
            return {
                (key if key in ARGUMENT_KEYS else operation(key)): self.values(
                    item, restore, code
                )
                for key, item in value.items()
            }
        if restore and type(value) in {int, float}:
            # Source aliases are integers, even when the source literal was a
            # decimal. Never recover an alias after floating-point rounding.
            candidate = str(abs(value))
            if type(value) is float and 732846000000000000 <= abs(value) < 732847000000000000:
                raise ValueError("Numeric alias lost integer precision.")
            mapping = self.session.reverse_store.get(candidate)
            if mapping is not None and mapping.token_type == TokenType.NUMBER:
                if not re.fullmatch(r"-?(?:0|[1-9]\d*)(?:\.\d+)?(?:[eE][+-]?\d+)?", mapping.original):
                    raise ValueError("Source literal cannot be restored as a JSON number.")
                original = json.loads(mapping.original)
                if type(original) is float and not math.isfinite(original):
                    raise ValueError("Source literal is not a finite JSON number.")
                return -original if value < 0 else original
            # Detect invented numeric aliases with the same strict policy used
            # for strings, while leaving ordinary JSON scalars unchanged.
            self.restore(str(value))
        return value

    def walk(self, value, restore=False, code=False, schema_root=None):
        if schema_root is None:
            schema_root = value
        if isinstance(value, str):
            return self.restore(value) if restore else self.mask(value, code)
        if isinstance(value, list):
            return [self.walk(item, restore, code, schema_root) for item in value]
        if not isinstance(value, dict):
            return value
        kind = value.get("type", "")
        if not isinstance(kind, str):
            kind = ""
        # Signed/encrypted reasoning is decoded before the attachment check:
        # redacted_thinking carries opaque `data` ciphertext by design.
        if kind in {"thinking", "redacted_thinking", "reasoning"}:
            key = self._opaque_key(value)
            if restore:
                self.opaque.add(key)
            elif key not in self.opaque:
                raise ValueError(
                    "Unrecognized signed/encrypted reasoning; start a new conversation."
                )
            return deepcopy(value)
        if (
            kind in BLOCKED_TYPES
            or any(k in value for k in ("image_url", "file_data", "file_id"))
            # `data` alone also occurs in ordinary tool results (for example a
            # JSON field named "data"); only attachment metadata blocks it.
            or (
                "data" in value
                and any(k in value for k in ("mimeType", "mime_type", "media_type"))
            )
        ):
            raise ValueError(
                "Binary/remote attachments are unsupported by the privacy gateway."
            )
        if any(key in value for key in {"signature", "encrypted_content"}):
            raise ValueError(
                "Opaque fields outside recognized reasoning are unsupported."
            )
        result: dict[str, Any] = {}
        for key, item in value.items():
            if key == "$schema" and isinstance(item, str):
                # Public JSON Schema dialect URIs stay usable. Anything else is
                # private data and is masked/restored like ordinary text instead
                # of rejecting the whole request.
                if item in JSON_SCHEMA_DIALECTS:
                    result[key] = item
                elif restore:
                    result[key] = self.restore(item)
                else:
                    result[key] = self.mask(item)
            elif key in {"name", "tool_name"}:
                if not isinstance(item, str):
                    raise ValueError("Tool names must be strings.")
                result[key] = (
                    self.restore(item)
                    if restore
                    else item
                    if item in TOOL_NAMES
                    else self.mask(item, code=True)
                )
            elif (
                key == "format"
                and kind == "custom"
            ):
                if item == {"type": "text"}:
                    result[key] = {"type": "text"}
                    continue
                if not isinstance(item, dict):
                    raise ValueError("Unrecognized custom tool grammar format.")
                definition = item.get("definition", "")
                if (
                    set(item) != {"type", "syntax", "definition"}
                    or item.get("type") != "grammar"
                    or item.get("syntax") != "lark"
                    or not isinstance(definition, str)
                ):
                    raise ValueError("Unrecognized custom tool grammar format.")
                normalized = definition.replace("\r\n", "\n").strip()
                allowed = (
                    value.get("name") == "exec"
                    and normalized == EXEC_GRAMMAR.strip()
                    or value.get("name") == "apply_patch"
                    and sha256(normalized.encode()).hexdigest() in PATCH_GRAMMAR_HASHES
                )
                if not allowed:
                    raise ValueError(
                        "Unrecognized custom tool grammar; request was not forwarded."
                    )
                result[key] = deepcopy(
                    item
                )  # Only pinned public CLI grammars may pass unchanged.
            elif (
                key == "format"
                and isinstance(item, str)
                and item
                in {
                    "uri",
                    "uri-reference",
                    "date",
                    "time",
                    "date-time",
                    "duration",
                    "uuid",
                    "email",
                    "hostname",
                    "ipv4",
                    "ipv6",
                    "regex",
                }
            ):
                result[key] = item
            elif key == "cache_control":
                validate_cache_control(item)
                result[key] = deepcopy(item)
            elif key in PROTOCOL:
                result[key] = self.protocol_value(value, key, item, restore)
            elif key == "arguments" and isinstance(item, str):
                if not item.strip():
                    result[key] = ""
                    continue
                result[key] = json.dumps(
                    self.values(json.loads(item), restore, code=True),
                    ensure_ascii=False,
                    separators=(",", ":"),
                )
            elif key == "input" and kind == "custom_tool_call":
                result[key] = self.walk(item, restore, code=True)
            elif key == "input" and kind == "tool_use":
                result[key] = self.values(item, restore, code=True)
            elif key == "output" and kind in {
                "function_call_output",
                "custom_tool_call_output",
            }:
                result[key] = self.tool_output(item, restore)
            elif key == "content" and kind == "tool_result":
                result[key] = self.tool_output(item, restore)
            elif key == "content" and value.get("role") == "tool":
                result[key] = self.tool_output(item, restore)
            elif (key == "patternProperties" and item) or (
                key == "pattern" and isinstance(item, str) and kind in SCHEMA_TYPES
            ):
                raise ValueError(
                    "JSON Schema pattern constraints cannot safely preserve private names."
                )
            elif key in {"parameters", "input_schema", "schema"} and isinstance(
                item, (dict, bool)
            ):
                self.validate_schema(item)
                result[key] = self.walk(item, restore, schema_root=item)
            elif key in SCHEMA_NAME_KEYWORDS:
                if not isinstance(item, dict):
                    raise ValueError("Schema name maps must be objects.")
                result[key] = {
                    (
                        self.restore(k)
                        if restore
                        else k
                        if k in ARGUMENT_KEYS
                        else self.mask(k, code=True)
                    ): (
                        [self.schema_name(name, restore) for name in v]
                        if key in {"dependentRequired", "dependencies"}
                        and isinstance(v, list)
                        else self.walk(v, restore, schema_root=schema_root)
                    )
                    for k, v in item.items()
                }
            elif key == "required":
                result[key] = [
                    self.restore(k)
                    if restore
                    else k
                    if k in ARGUMENT_KEYS
                    else self.mask(k, code=True)
                    for k in item
                ]
            elif key == "$ref" and isinstance(item, str):
                result[key] = self.schema_reference(item, schema_root, restore)
            elif key in DATA_KEYWORDS:
                # enum/const/default/examples hold arbitrary JSON data. Protocol
                # and schema exceptions must not apply inside them, or private
                # values under keys like id/type/model/cache_control leak.
                result[key] = self.walk_data(item, restore)
            else:
                if (kind in {"text", "input_text", "output_text", "refusal"}
                    or "role" in value) and key not in {"content", "tool_calls"}:
                    result[key] = self.walk_data(item, restore)
                else:
                    result[key] = self.walk(item, restore, code, schema_root)
        return result

    def schema_reference(self, reference, root, restore=False):
        if reference == "#":
            return reference
        if not reference.startswith("#") or re.search(r"%(?![0-9A-Fa-f]{2})", reference):
            raise ValueError("Remote schema references or malformed pointers are unsupported.")
        pointer = urllib.parse.unquote(reference[1:], errors="strict")
        if not pointer.startswith("/"):
            raise ValueError("Remote schema references and named anchors are unsupported.")
        node = root
        name_map = False
        transformed = []
        for segment in pointer[1:].split("/"):
            if re.search(r"~(?![01])", segment):
                raise ValueError("Malformed schema pointer.")
            original = segment.replace("~1", "/").replace("~0", "~")
            decoded = self.schema_name(original, restore) if name_map else original
            transformed.append(decoded.replace("~", "~0").replace("/", "~1"))
            next_name_map = not name_map and isinstance(node, dict) and original in SCHEMA_NAME_KEYWORDS
            try:
                node = node[int(original)] if isinstance(node, list) else node[original]
            except (KeyError, IndexError, TypeError, ValueError):
                raise ValueError("Schema reference does not resolve.") from None
            name_map = next_name_map
        return "#" + urllib.parse.quote("/" + "/".join(transformed), safe="/~$")

    def tool_output(self, value, restore=False):
        """Content blocks have public envelopes; their extra payloads are data."""
        if isinstance(value, str):
            return self.restore(value) if restore else self.mask(value, code=True)
        if not isinstance(value, list):
            return self.walk_data(value, restore)
        result = []
        for block in value:
            if isinstance(block, dict) and block.get("type") in {
                "text", "input_text", "output_text", "refusal",
            }:
                public_fields = {"type", "text", "refusal", "cache_control"}
                transformed = self.walk(
                    {key: item for key, item in block.items() if key in public_fields},
                    restore, code=True,
                )
                for key, item in block.items():
                    if key not in public_fields:
                        name = self.restore(key) if restore else self.mask(key, code=True)
                        transformed[name] = self.walk_data(item, restore)
                result.append(transformed)
            else:
                result.append(self.walk(block, restore, code=True))
        return result

    def protocol_value(self, envelope, key, item, restore):
        """Public tags apply only to their envelopes, never arbitrary data."""
        kind = envelope.get("type")
        if not isinstance(kind, str):
            kind = ""
        kinds = {
            "text", "input_text", "output_text", "refusal", "message",
            "tool_use", "tool_result", "function_call", "function_call_output",
            "custom_tool_call", "custom_tool_call_output", "tool_namespace",
            "tool_reference", "function", "custom", "json_schema", "json_object",
        } | SCHEMA_TYPES
        if key == "type" and isinstance(item, list) and all(
            isinstance(tag, str) and tag in SCHEMA_TYPES for tag in item
        ):
            return deepcopy(item)
        keep = key == "type" and isinstance(item, str) and item in kinds
        if key == "role":
            keep = "content" in envelope and isinstance(item, str) and item in {
                "system", "developer", "user", "assistant", "tool",
            }
        elif key == "id":
            keep = kind in {"tool_use", "function_call", "custom_tool_call", "message"}
        elif key == "call_id":
            keep = kind in {"function_call", "function_call_output", "custom_tool_call", "custom_tool_call_output"}
        elif key == "tool_use_id":
            keep = kind == "tool_result"
        elif key == "tool_call_id":
            keep = envelope.get("role") == "tool" and "content" in envelope
        elif key in {"effort", "verbosity", "syntax"}:
            allowed = {
                "effort": {"none", "minimal", "low", "medium", "high", "xhigh", "max"},
                "verbosity": {"low", "medium", "high"},
                "syntax": {"lark", "regex"},
            }
            keep = isinstance(item, str) and item in allowed[key]
        if keep:
            if not isinstance(item, str):
                raise ValueError("Protocol identifiers must be text.")
            return item
        return self.walk_data(item, restore)

    def schema_name(self, name, restore=False):
        if not isinstance(name, str):
            raise ValueError("Schema property names must be text.")
        return (
            self.restore(name)
            if restore
            else name
            if name in ARGUMENT_KEYS
            else self.mask(name, code=True)
        )

    def validate_schema(self, schema):
        if isinstance(schema, bool):
            return
        if not isinstance(schema, dict):
            raise ValueError("Schema must be an object or boolean.")
        if schema.get("patternProperties") or "pattern" in schema:
            raise ValueError("JSON Schema pattern constraints are unsupported.")
        if set(schema) & {"minLength", "maxLength", "format"}:
            raise ValueError("JSON Schema string length/format constraints cannot preserve aliases.")
        for key, item in schema.items():
            if key in SCHEMA_NAME_KEYWORDS and key != "dependentRequired":
                if not isinstance(item, dict):
                    raise ValueError("Schema name maps must be objects.")
                for child in item.values():
                    if key == "dependencies" and isinstance(child, list):
                        continue
                    self.validate_schema(child)
            elif key in {
                "items",
                "additionalItems",
                "unevaluatedItems",
                "contentSchema",
                "additionalProperties",
                "unevaluatedProperties",
                "contains",
                "not",
                "if",
                "then",
                "else",
                "propertyNames",
            }:
                for child in item if isinstance(item, list) else [item]:
                    self.validate_schema(child)
            elif key in {"allOf", "anyOf", "oneOf", "prefixItems"}:
                if not isinstance(item, list):
                    raise ValueError("Schema alternatives must be arrays.")
                for child in item:
                    self.validate_schema(child)

    def walk_data(self, value, restore=False):
        """Mask/restore arbitrary JSON data (enum/const/default/examples).

        Protocol and schema exceptions do not apply here: keys such as id,
        type, model or cache_control inside user data are still private.
        """
        if isinstance(value, str):
            return self.restore(value) if restore else self.mask(value)
        if isinstance(value, list):
            return [self.walk_data(item, restore) for item in value]
        if not isinstance(value, dict):
            return value
        return {
            (
                self.restore(key)
                if restore
                else key
                if key in ARGUMENT_KEYS
                else self.mask(key, code=True)
            ): self.walk_data(item, restore)
            for key, item in value.items()
        }

    def safeguards(self, value, position="envelope"):
        """Support the observed classifier envelope; reject unknown controls."""
        if isinstance(value, list):
            if position != "envelope" or any(not isinstance(item, dict) for item in value):
                raise ValueError("Unsupported safety policy envelope.")
            return [self.safeguards(item, position) for item in value]
        if not isinstance(value, dict):
            raise ValueError("Unsupported safety policy envelope.")
        fields = {
            "envelope": {"type", "classifier_context"},
            "context": {"permission_mode", "platform", "live_cwd", "rules"},
            "rules": {"allow", "deny", "ask"},
            "rule": {"rule", "source"},
        }
        enums = {
            "type": {"dangerous_tool_use"},
            "permission_mode": {"auto", "default", "acceptEdits", "plan", "dontAsk", "bypassPermissions"},
            "platform": {"windows", "linux", "darwin"},
            "source": {"toolsNarrowing", "userSettings", "projectSettings", "localSettings", "commandLine"},
        }
        if set(value) - fields[position]:
            raise ValueError("Unsupported safety policy fields.")
        result: dict[str, Any] = {}
        for key, item in value.items():
            if key in enums:
                if not isinstance(item, str) or item not in enums[key]:
                    raise ValueError("Unsupported safety protocol tag.")
                result[key] = item
            elif key == "classifier_context":
                result[key] = self.safeguards(item, "context")
            elif key == "rules":
                result[key] = self.safeguards(item, "rules")
            elif position == "rules":
                if not isinstance(item, list):
                    raise ValueError("Safety rules must be arrays.")
                result[key] = [self.safeguards(rule, "rule") for rule in item]
            elif key in {"rule", "live_cwd"}:
                if not isinstance(item, str):
                    raise ValueError("Safety operands must be text.")
                result[key] = item if key == "rule" and item in TOOL_NAMES else self.mask(item)
            else:
                raise ValueError("Unsupported safety policy field.")
        return result

    def tool_choice(self, value, dialect):
        if isinstance(value, str):
            if value not in {"auto", "none", "required", "any"}:
                raise ValueError("Unsupported tool choice.")
            return value
        if not isinstance(value, dict):
            raise ValueError("Tool choice must be text or an object.")
        kind = value.get("type")
        if dialect == "claude":
            allowed = {"type", "disable_parallel_tool_use"} | ({"name"} if kind == "tool" else set())
            if not isinstance(kind, str) or kind not in {"auto", "none", "any", "tool"} or set(value) - allowed:
                raise ValueError("Unsupported Claude tool choice.")
            if "disable_parallel_tool_use" in value and not isinstance(value["disable_parallel_tool_use"], bool):
                raise ValueError("Invalid parallel tool choice control.")
            result = deepcopy(value)
            if kind == "tool":
                if not isinstance(value.get("name"), str):
                    raise ValueError("Tool choice requires a tool name.")
                result["name"] = self.walk({"name": value["name"]})["name"]
            return result
        if kind != "function":
            raise ValueError("Unsupported function tool choice.")
        if dialect == "chat_completions":
            if set(value) != {"type", "function"} or not isinstance(value["function"], dict) or set(value["function"]) != {"name"}:
                raise ValueError("Invalid function tool choice.")
            name = value["function"].get("name")
        else:
            if set(value) != {"type", "name"}:
                raise ValueError("Invalid function tool choice.")
            name = value.get("name")
        if not isinstance(name, str):
            raise ValueError("Tool choice requires a tool name.")
        return self.walk(value)

    def context_management(self, value):
        if not isinstance(value, dict) or set(value) != {"edits"} or not isinstance(value["edits"], list):
            raise ValueError("Unsupported context management.")
        result = []
        for edit in value["edits"]:
            if not isinstance(edit, dict):
                raise ValueError("Context edits must be objects.")
            kind = edit.get("type")
            if kind == "clear_tool_uses_20250919":
                fields = {"type", "trigger", "keep", "clear_at_least", "exclude_tools", "clear_tool_inputs"}
                thresholds = {"trigger": "input_tokens", "keep": "tool_uses", "clear_at_least": "input_tokens"}
            elif kind == "clear_thinking_20251015":
                fields = {"type", "keep"}
                thresholds = {"keep": "thinking_turns"}
            else:
                raise ValueError("Unsupported context edit type.")
            if set(edit) - fields:
                raise ValueError("Unsupported context edit controls.")
            transformed = deepcopy(edit)
            for key, tag in thresholds.items():
                if key not in edit:
                    continue
                item = edit[key]
                if kind == "clear_thinking_20251015" and key == "keep" and item == "all":
                    continue
                if (not isinstance(item, dict) or set(item) != {"type", "value"}
                    or item.get("type") != tag or type(item.get("value")) is not int
                    or item["value"] < (1 if tag == "thinking_turns" else 0)):
                    raise ValueError("Invalid context edit threshold.")
            if "clear_tool_inputs" in edit and not isinstance(edit["clear_tool_inputs"], bool):
                raise ValueError("Invalid clear tool inputs control.")
            if "exclude_tools" in edit:
                names = edit["exclude_tools"]
                if not isinstance(names, list) or any(not isinstance(name, str) for name in names):
                    raise ValueError("Tool exclusions must be tool names.")
                transformed["exclude_tools"] = [self.walk({"name": name})["name"] for name in names]
            result.append(transformed)
        return {"edits": result}

    def request(self, payload: dict[str, Any], *, dialect=None) -> dict[str, Any]:
        request_dialect = dialect or ("claude" if "messages" in payload else "codex")
        validate_request(payload, request_dialect)
        fields = (
            TOP_FIELDS | {"max_completion_tokens", "stop", "stream_options", "reasoning_effort", "response_format"}
            if dialect == "chat_completions"
            else TOP_FIELDS
        )
        if set(payload) - fields:
            raise ValueError("Unsupported request fields; request was not forwarded.")
        if payload.get("background") or payload.get("truncation") == "auto":
            raise ValueError("Background/server-side truncation is unsupported.")
        if dialect in {"responses", "chat_completions"}:
            validate_api_options(payload, dialect)
            if "input" in payload and "messages" in payload:
                raise ValueError("Mixed API dialects are unsupported.")
            if dialect == "chat_completions" and "system" in payload:
                raise ValueError(
                    "Chat Completions uses system messages, not a system field."
                )
            options = payload.get("stream_options")
            if options is not None and (
                not isinstance(options, dict)
                or set(options) - {"include_usage"}
                or not isinstance(options.get("include_usage"), bool)
            ):
                raise ValueError("Unsupported stream options.")
            for tool in payload.get("tools", []):
                if not isinstance(tool, dict) or tool.get("type") != "function":
                    raise ValueError(
                        "API mode supports local function tools only; remote tools are blocked."
                    )
            if dialect == "responses" and "input" not in payload:
                raise ValueError("Responses requires an input payload.")
            if dialect == "chat_completions" and "messages" not in payload:
                raise ValueError("Chat Completions requires messages.")

        # Seed code aliases before prompt references in this request.
        def seed(value):
            if isinstance(value, str):
                self.mask(value)
            elif isinstance(value, list):
                for item in value:
                    seed(item)
            elif isinstance(value, dict):
                if value.get("type") in {
                    "tool_result",
                    "function_call_output",
                    "tool_use",
                    "function_call",
                    "custom_tool_call",
                    "custom_tool_call_output",
                }:
                    self.walk(value)
                else:
                    for item in value.values():
                        seed(item)

        seed(payload.get("messages", payload.get("input", [])))
        result = {}
        for key, value in payload.items():
            if key == "system" and "messages" in payload:
                result[key] = self.claude_system(value)
                continue
            if key == "safeguards":
                result[key] = self.safeguards(value)
                continue
            if key == "context_management":
                if request_dialect != "claude":
                    raise ValueError("Context editing requires the Claude dialect.")
                result[key] = self.context_management(value)
                continue
            if key in {"client_metadata", "metadata"}:
                continue  # Optional diagnostics are not required for inference.
            if key == "tool_choice":
                result[key] = self.tool_choice(value, request_dialect)
                continue
            if key in {
                "messages",
                "input",
                "instructions",
                "system",
                "tools",
                "text",
                "stop_sequences",
                "stop",
                "tool_choice",
                "output_config",
                "response_format",
                "context_management",
                "safeguards",
            }:
                result[key] = self.walk(value)
            elif key in {"prompt_cache_key", "safety_identifier"}:
                result[key] = sha256(str(value).encode()).hexdigest()
            else:
                result[key] = deepcopy(value)
        if "input" in result:
            result["store"] = False
            result["instructions"] = PRIVACY_INSTRUCTION + result.get(
                "instructions", ""
            )
        elif "messages" in result and dialect == "chat_completions":
            if "system" in result:
                raise ValueError(
                    "Chat Completions uses system messages, not a system field."
                )
            result["messages"].insert(
                0, {"role": "system", "content": PRIVACY_INSTRUCTION}
            )
        elif "messages" in result:
            system = result.get("system", [])
            if isinstance(system, str):
                system = [{"type": "text", "text": system}]
            result["system"] = [*system, {"type": "text", "text": PRIVACY_INSTRUCTION}]
        for tool in result.get("tools", []):
            if tool.get("name") in TOOL_DESCRIPTIONS:
                tool["description"] = TOOL_DESCRIPTIONS[tool["name"]]
        return result

    def claude_system(self, value):
        if isinstance(value, str):
            if value.startswith(CLAUDE_ATTRIBUTION_PREFIX):
                raise ValueError(
                    "Claude attribution must be a separate first system block."
                )
            return self.walk(value)
        if not isinstance(value, list):
            raise ValueError("Unsupported Claude system payload.")
        result: list[dict[str, Any]] = []
        for index, block in enumerate(value):
            text = block.get("text", "") if isinstance(block, dict) else ""
            if isinstance(text, str) and text.startswith(CLAUDE_ATTRIBUTION_PREFIX):
                if (
                    index != 0
                    or block.get("type") != "text"
                    or set(block) - {"type", "text", "cache_control"}
                    or not CLAUDE_ATTRIBUTION.fullmatch(text)
                ):
                    raise ValueError(
                        "Unrecognized Claude attribution; request was not forwarded."
                    )
                result.append({"type": "text", "text": text})
                if "cache_control" in block:
                    control = block["cache_control"]
                    if (
                        not isinstance(control, dict)
                        or control.get("type") != "ephemeral"
                        or set(control) - {"type", "ttl"}
                        or control.get("ttl", "5m") not in {"5m", "1h"}
                    ):
                        raise ValueError("Unrecognized attribution cache control.")
                    result[-1]["cache_control"] = deepcopy(control)
            else:
                result.append(self.walk(block))
        return result

    def response(self, body: bytes, content_type: str, *, dialect=None) -> bytes:
        media_type = content_type.split(";", 1)[0].strip().lower()
        if media_type != "text/event-stream":
            payload = json.loads(body)
            if not isinstance(payload, dict):
                raise ValueError("Upstream response must be a JSON object.")
            return json.dumps(
                self.walk(payload, restore=True), ensure_ascii=False
            ).encode()
        events: list[tuple[list[str], dict[str, Any] | None]] = []
        stream = body.decode("utf-8-sig").replace("\r\n", "\n").replace("\r", "\n")
        for frame in stream.split("\n\n"):
            # SSE line endings do not include Unicode separators inside JSON strings.
            lines = frame.replace("\r\n", "\n").split("\n")
            data = "\n".join(
                line[5:].lstrip() for line in lines if line.startswith("data:")
            )
            if not data or data == "[DONE]":
                events.append((lines, None))
            else:
                event = json.loads(data)
                if not isinstance(event, dict):
                    raise ValueError("SSE events must be JSON objects.")
                events.append((lines, event))
        # Fold each text/JSON stream before restoration (tokens can span any delta).
        groups: dict[tuple, list[tuple[int, dict, str]]] = {}
        thinking: dict[int, dict] = {}
        key: tuple
        for index, (_, event) in enumerate(events):
            if not isinstance(event, dict):
                continue
            if dialect == "chat_completions":
                choices = event.get("choices", [])
                if not isinstance(choices, list):
                    raise ValueError("Invalid Chat Completions choices.")
                for choice in choices:
                    if not isinstance(choice, dict) or not isinstance(choice.get("index"), int):
                        raise ValueError("Invalid Chat Completions choice.")
                    chat_delta = choice.get("delta", {})
                    if not isinstance(chat_delta, dict):
                        raise ValueError("Invalid Chat Completions delta.")
                    calls = chat_delta.get("tool_calls", [])
                    if not isinstance(calls, list):
                        raise ValueError("Invalid Chat Completions tool calls.")
                    for field in ("content", "reasoning_content", "refusal"):
                        if isinstance(chat_delta.get(field), str):
                            groups.setdefault(
                                ("chat", choice["index"], field), []
                            ).append((index, chat_delta, field))
                    for call in calls:
                        if not isinstance(call, dict) or not isinstance(call.get("index"), int):
                            raise ValueError("Invalid Chat Completions tool call.")
                        function = call.get("function", {})
                        if not isinstance(function, dict):
                            raise ValueError("Invalid Chat Completions function.")
                        for field in ("name", "arguments"):
                            if isinstance(function.get(field), str):
                                groups.setdefault(
                                    (
                                        "chat_tool",
                                        choice["index"],
                                        call["index"],
                                        field,
                                    ),
                                    [],
                                ).append((index, function, field))
                continue
            kind = event.get("type", "")
            delta = event.get("delta")
            if kind == "content_block_start" and not isinstance(event.get("content_block"), dict):
                raise ValueError("Invalid Claude content block.")
            if kind == "content_block_delta" and not isinstance(delta, dict):
                raise ValueError("Invalid Claude content delta.")
            if (
                kind == "content_block_start"
                and event.get("content_block", {}).get("type") == "thinking"
            ):
                thinking[event["index"]] = deepcopy(event["content_block"])
            if (
                kind == "content_block_delta"
                and event.get("index") in thinking
                and isinstance(delta, dict)
            ):
                block = thinking[event["index"]]
                for field in ("thinking", "signature"):
                    if field in delta:
                        if not isinstance(delta[field], str):
                            raise ValueError("Invalid Claude thinking delta.")
                        block[field] = block.get(field, "") + delta[field]
            if kind == "content_block_delta" and isinstance(delta, dict):
                field = (
                    "partial_json"
                    if delta.get("type") == "input_json_delta"
                    else "text"
                )
                if field not in delta:
                    continue  # signed thinking is kept exactly as received
                if not isinstance(delta[field], str):
                    raise ValueError("Invalid Claude text/JSON delta.")
                target = delta
                key = (kind, event.get("index"), field)
            elif kind in {
                "response.output_text.delta",
                "response.refusal.delta",
                "response.reasoning_summary_text.delta",
                "response.function_call_arguments.delta",
                "response.custom_tool_call_input.delta",
            }:
                if not isinstance(delta, str):
                    raise ValueError("Invalid Responses delta.")
                target, field = event, "delta"
                key = (
                    kind,
                    event.get("item_id"),
                    event.get("output_index"),
                    event.get("content_index"),
                    event.get("summary_index"),
                )
            else:
                continue
            groups.setdefault(key, []).append((index, target, field))
        for block in thinking.values():
            self.opaque.add(self._opaque_key(block))
        for group in groups.values():
            combined = "".join(target[field] for _, target, field in group)
            field = group[0][2]
            if (
                field == "partial_json"
                or dialect == "chat_completions"
                and field == "arguments"
                or group[0][1].get("type") == "response.function_call_arguments.delta"
            ):
                restored = (
                    combined
                    if not combined.strip()
                    else json.dumps(
                        self.values(json.loads(combined), restore=True),
                        ensure_ascii=False,
                    )
                )
            else:
                restored = self.restore(combined)
            for offset, (_, target, field) in enumerate(group):
                target[field] = restored if offset == 0 else ""
        output = []
        for lines, event in events:
            if event is None:
                if lines:
                    output.append("\n".join(lines) + "\n\n")
                continue
            # Deltas have already been restored; do not recursively restore twice.
            if dialect == "chat_completions":
                pass  # Chat delta text/names/arguments were restored above.
            elif event.get("type") not in {
                "content_block_delta",
                "response.output_text.delta",
                "response.refusal.delta",
                "response.reasoning_summary_text.delta",
                "response.function_call_arguments.delta",
                "response.custom_tool_call_input.delta",
            }:
                event = self.walk(event, restore=True)
            headers = [line for line in lines if not line.startswith("data:")]
            output.append(
                "\n".join(headers + ["data: " + json.dumps(event, ensure_ascii=False)])
                + "\n\n"
            )
        return "".join(output).encode()


class PrivacyGateway(ThreadingHTTPServer):
    daemon_threads = True

    def __init__(
        self,
        address,
        token: str,
        upstreams=None,
        state_dir: Path | None = None,
        api_upstreams=None,
        mapping_limit=100_000,
        audit_path: Path | None = None,
        max_active_requests=32,
        max_provider_requests=8,
        mask_numbers=False,
    ):
        if type(mask_numbers) is not bool:
            raise ValueError("mask_numbers must be a boolean.")
        self.mask_numbers = mask_numbers
        if address[0] != "127.0.0.1":
            raise ValueError("Gateway must bind to IPv4 loopback.")
        if (
            not isinstance(mapping_limit, int)
            or isinstance(mapping_limit, bool)
            or mapping_limit < 1
        ):
            raise ValueError("Mapping limit must be a positive integer.")
        self.mapping_limit = mapping_limit
        for limit in (max_active_requests, max_provider_requests):
            if type(limit) is not int or limit < 1:
                raise ValueError("Request admission limits must be positive integers.")
        self.max_active_requests = max_active_requests
        self.max_provider_requests = max_provider_requests
        self.admission = Condition(RLock())
        self.admitted_requests = 0
        self.provider_admitted: dict[str, int] = {}
        self.closing = False
        self.token = token
        self.upstreams = dict(UPSTREAMS if upstreams is None else upstreams)
        # Explicit API-key modes are opt-in at construction. They are never
        # enabled by subscription installation and never share credentials.
        self.api_upstreams = dict(api_upstreams or {})
        for agent, origin in self.api_upstreams.items():
            if agent not in API_AUTH_PREFIXES:
                raise ValueError(f"Unsupported API mode: {agent}")
            loopback = isinstance(origin, str) and re.fullmatch(
                r"http://127\.0\.0\.1:[0-9]{1,5}", origin
            )
            if origin != API_UPSTREAMS[agent] and not loopback:
                raise ValueError("API upstream must be a fixed HTTPS origin.")
            self.upstreams[agent] = origin
        self.sessions: dict[str, GatewaySession] = {}
        self.sessions_lock = RLock()
        self.provider_locks = {agent: RLock() for agent in self.upstreams}
        self.state_dir = state_dir
        if state_dir:
            state_dir.mkdir(parents=True, exist_ok=True)
            state_dir.chmod(0o700)
        self.audit = AuditStore(audit_path) if audit_path is not None else None
        self.audit_write_errors = 0
        super().__init__(address, GatewayHandler)

    def try_admit(self, agent):
        """Reserve an inference slot without waiting or reading the body."""
        with self.admission:
            if (self.closing or self.admitted_requests >= self.max_active_requests
                or self.provider_admitted.get(agent, 0) >= self.max_provider_requests):
                return False
            self.admitted_requests += 1
            self.provider_admitted[agent] = self.provider_admitted.get(agent, 0) + 1
            return True

    def release_admission(self, agent):
        with self.admission:
            self.admitted_requests -= 1
            self.provider_admitted[agent] -= 1
            self.admission.notify_all()

    def drain_and_shutdown(self):
        """Keep health available until all admitted inference has finished."""
        with self.admission:
            self.closing = True
            self.admission.wait_for(lambda: self.admitted_requests == 0)
        self.shutdown()

    def session_diagnostics(self):
        """Return aggregate limits and lifetimes, never mappings or credentials."""
        with self.admission:
            active = self.admitted_requests
            admitted = dict(self.provider_admitted)
        providers = {}
        for agent in sorted(self.upstreams):
            with self.provider_locks[agent]:
                session = self.sessions.get(agent)
                item: dict[str, Any] = {"active_requests": admitted.get(agent, 0),
                        "mapping_limit": self.mapping_limit, "mapping_count": 0,
                        "ttl_seconds": None, "expires_at": None, "expired": False}
                if session is not None:
                    with session.lock:
                        item.update(mapping_count=len(session.session.forward_store),
                                    ttl_seconds=session.session.ttl_seconds,
                                    expires_at=session.session.last_accessed + session.session.ttl_seconds,
                                    expired=session.session.is_expired())
                providers[agent] = item
        return {"active_requests": active, "max_active_requests": self.max_active_requests,
                "max_provider_requests": self.max_provider_requests, "providers": providers}

    def get_session(self, agent):
        with self.provider_locks[agent]:
            current = self.sessions.get(agent)
            if current is not None:
                # Serialize with an in-flight request before dropping state.
                with current.lock:
                    if not current.session.generator.closed and (
                        current.active_requests or not current.session.is_expired()
                    ):
                        return current
                    # An always-on daemon must apply the same idle TTL as a
                    # restarted one: drop expired aliases and reasoning
                    # provenance instead of silently reusing (and reviving)
                    # them via save().
                    current.session.clear()
                    current.opaque.clear()
                    current.encryption = None
                del self.sessions[agent]
            path = (
                self.state_dir / f"{agent}-symbols-v2.enc" if self.state_dir else None
            )
            saved = None
            if path and path.exists():
                try:
                    saved = load_session(path, self.token, "gateway")
                except SessionExpiredError:
                    saved = None
            session = GatewaySession(saved, self.mapping_limit, mask_numbers=self.mask_numbers)
            # Reasoning provenance is only meaningful while the matching alias
            # table is alive. Expired/missing snapshots start fresh, so stale
            # digests must not be loaded into the new table.
            if saved is not None and path and path.with_suffix(".opaque.json").exists():
                digests = json.loads(
                    path.with_suffix(".opaque.json").read_text(encoding="utf-8")
                )
                if not isinstance(digests, list) or any(
                    not isinstance(x, str) or not re.fullmatch(r"[a-f0-9]{64}", x)
                    for x in digests
                ):
                    raise ValueError("Invalid persisted reasoning state.")
                session.opaque = set(digests)
            self.sessions[agent] = session
            return session

    def save(self, agent, session):
        if session.session.is_expired() and not session.active_requests:
            # Do not revive an expired session via touch(). Drop its aliases
            # and provenance; the next get_session() replaces the registry
            # entry after its own expiry check, so no registry lock is taken
            # here (avoids lock inversion with the request path).
            session.session.clear()
            session.opaque.clear()
            return
        session.session.touch()
        if self.state_dir:
            path = self.state_dir / f"{agent}-symbols-v2.enc"
            if session.encryption is None:
                session.encryption = SnapshotEncryption(self.token)
            save_session(
                path, session.session, self.token, encryption=session.encryption
            )
            _atomic_json(path.with_suffix(".opaque.json"), sorted(session.opaque))
            path.with_suffix(".opaque.json").chmod(0o600)

    def reset(self, agent="all"):
        agents = sorted(self.upstreams) if agent == "all" else [agent]
        if any(name not in self.upstreams for name in agents):
            raise ValueError("Unknown provider.")
        with ExitStack() as stack:
            for name in agents:
                stack.enter_context(self.provider_locks[name])
            current = [(name, self.sessions.get(name)) for name in agents]
            for _, session in current:
                if session is not None:
                    stack.enter_context(session.lock)
                    if session.active_requests:
                        raise ValueError(
                            "Provider has active requests; retry after they finish."
                        )
            for name, session in current:
                if self.state_dir:
                    path = self.state_dir / f"{name}-symbols-v2.enc"
                    path.unlink(missing_ok=True)
                    path.with_suffix(".opaque.json").unlink(missing_ok=True)
                if session is not None:
                    session.session.clear()
                    session.opaque.clear()
                    session.encryption = None
                    del self.sessions[name]

    def server_close(self):
        with self.admission:
            self.closing = True
        super().server_close()
        with self.admission:
            self.admission.wait_for(lambda: self.admitted_requests == 0)
        for session in self.sessions.values():
            with session.lock:
                session.session.clear()
                session.opaque.clear()
                session.encryption = None
        self.sessions.clear()


class GatewayHandler(BaseHTTPRequestHandler):
    server: PrivacyGateway
    audit_metadata: dict[str, Any] | None = None
    protocol_version = "HTTP/1.0"
    timeout = 60

    def log_message(self, *_):
        pass  # Never log headers, prompts, replies or tokens.

    def send_body(self, status, body, content_type="application/json"):
        if self.audit_metadata is not None:
            self.audit_metadata["status"] = status
            self.audit_metadata["output_bytes"] = len(body)
        self.send_response(status)
        self.send_header("Content-Type", content_type)
        self.send_header("Content-Length", str(len(body)))
        self.send_header("Cache-Control", "no-store")
        for key, value in getattr(self, "response_headers", {}).items():
            self.send_header(key, value)
        self.end_headers()
        self.wfile.write(body)

    def capture_response_headers(self, headers):
        self.response_headers = {
            key: value
            for key, value in headers.items()
            if key.lower() in {"retry-after", "x-should-retry"}
            or key.lower().startswith(("anthropic-ratelimit-", "x-ratelimit-"))
        }

    def authorized(self):
        return secrets.compare_digest(
            self.headers.get("X-SecureMCP-Token", "").encode(), self.server.token.encode()
        )

    def do_GET(self):
        if handle_admin(self):
            return
        if self.path == "/xai/v1/models":
            if not self.authorized():
                self.send_body(401, b'{"error":"Unauthorized"}')
                return
            if "xai" not in self.server.api_upstreams:
                self.send_body(400, b'{"error":"Explicit API mode required"}')
                return
            auth = self.headers.get("Authorization", "")
            if not auth.startswith(API_AUTH_PREFIXES["xai"]) or self.headers.get("x-api-key"):
                self.send_body(401, b'{"error":"xAI API key required"}')
                return
            try:
                body = fetch_catalog(self.server.api_upstreams["xai"], auth)
                self.send_body(200, body)
            except urllib.error.HTTPError as exc:
                self.capture_response_headers(exc.headers)
                status, body = sanitized_upstream_error(exc)
                self.send_body(status, body)
            except (ValueError, OSError, http.client.HTTPException):
                self.send_body(502, b'{"error":"Model catalog unavailable"}')
            return
        if self.path == "/health" and self.authorized():
            self.send_body(200, b'{"service":"secure-mcp-subscription-gateway"}')
        elif (
            self.authorized()
            and re.fullmatch(r"/codex/models(?:\?client_version=[\d.]+)?", self.path)
            and "codex" in self.server.upstreams
        ):
            auth = self.headers.get("Authorization", "")
            if not auth.startswith("Bearer eyJ") or self.headers.get("x-api-key"):
                self.send_body(401, b'{"error":"Subscription OAuth required"}')
                return
            try:
                request = urllib.request.Request(
                    self.server.upstreams["codex"] + self.path[len("/codex") :],
                    headers={
                        "Authorization": auth,
                        "chatgpt-account-id": self.headers.get(
                            "chatgpt-account-id", ""
                        ),
                    },
                )
                opener = urllib.request.build_opener(
                    urllib.request.ProxyHandler({}), NoRedirect()
                )
                with opener.open(request, timeout=30) as upstream:
                    body = upstream.read(LIMIT + 1)
                    if len(body) > LIMIT:
                        raise ValueError("Catalog size exceeded")
                    self.send_body(200, body)
            except urllib.error.HTTPError as exc:
                exc.close()
                self.send_body(
                    exc.code if exc.code in {401, 403, 429} else 502,
                    b'{"error":"Subscription catalog unavailable"}',
                )
            except (OSError, ValueError, http.client.HTTPException):
                self.send_body(502, b'{"error":"Subscription catalog unavailable"}')
        else:
            self.send_body(
                400 if self.authorized() else 401,
                b'{"error":"Unauthorized or unsupported endpoint"}',
            )

    def do_POST(self):
        # Only fixed inference routes enter the ledger; never store caller paths,
        # query strings, error bodies, arbitrary headers or request/response text.
        request_path = self.path.partition("?")[0]
        provider = (
            "claude" if request_path in {"/claude/v1/messages", "/claude/v1/messages/count_tokens"}
            else "codex" if request_path == "/codex/responses"
            else "xai" if request_path in {"/xai/v1/responses", "/xai/v1/chat/completions"}
            else None
        )
        self.audit_metadata = None
        if provider is None or self.server.audit is None:
            self._do_POST()
            return
        agent = {"claude": "Claude Code", "codex": "Codex", "xai": "xAI client"}[provider]
        subscription = {"claude": "claude_subscription", "codex": "chatgpt_subscription",
                        "xai": "api_key"}[provider]
        origin = urllib.parse.urlsplit(self.server.upstreams.get(provider, ""))
        destination = origin.scheme + "://" + origin.netloc.split("@")[-1] + origin.path
        try:
            request_id = self.server.audit.begin(
                agent, provider, subscription, request_path, destination,
            )
        except sqlite3.Error:
            self.server.audit_write_errors += 1
            self.send_body(503, b'{"error":"Audit storage unavailable; no request forwarded"}')
            return
        self.audit_metadata = {
            "agent": agent, "account_ref": None, "credential_ref": None,
            "model": None, "status": None, "outcome": "blocked",
            "upstream_attempted": 0, "input_bytes": 0, "masked_bytes": 0,
            "output_bytes": 0, "new_aliases": 0,
        }
        started = time.perf_counter()
        try:
            self._do_POST()
        finally:
            meta = self.audit_metadata
            meta["duration_ms"] = round((time.perf_counter() - started) * 1000, 2)
            if meta["status"] is None:
                meta["outcome"] = "incomplete"
            elif meta["status"] == 200:
                meta["outcome"] = "completed"
            try:
                self.server.audit.finish(request_id, meta)
            except sqlite3.Error:
                self.server.audit_write_errors += 1

    def _do_POST(self):
        if not self.authorized():
            self.send_body(401, b'{"error":"Unauthorized"}')
            return
        if self.path == "/shutdown":
            from threading import Thread

            with self.server.admission:
                self.server.closing = True
            try:
                self.send_body(200, b'{"stopping":true}')
            finally:
                Thread(target=self.server.drain_and_shutdown, daemon=True).start()
            return
        if self.path == "/reset":
            try:
                if self.headers.get("Transfer-Encoding") or self.headers.get(
                    "Content-Encoding"
                ):
                    raise ValueError("Unsupported encoding.")
                length = int(self.headers.get("Content-Length", "0"))
                if not 0 < length <= 1024:
                    raise ValueError("Invalid reset request.")
                payload = json.loads(self.rfile.read(length))
                if not isinstance(payload, dict) or set(payload) - {"agent"}:
                    raise ValueError("Invalid reset request.")
                agent = payload.get("agent", "all")
                if not isinstance(agent, str):
                    raise ValueError("Invalid provider.")
                self.server.reset(agent)
                self.send_body(200, b'{"reset":true}')
            except (ValueError, OSError):
                self.send_body(
                    409,
                    b'{"error":"Reset refused; stop active requests and retry with a valid provider"}',
                )
            return
        routes = {
            "/claude/v1/messages": ("claude", "/v1/messages"),
            "/claude/v1/messages/count_tokens": ("claude", "/v1/messages/count_tokens"),
            "/codex/responses": ("codex", "/responses"),
            "/xai/v1/responses": ("xai", "/v1/responses"),
            "/xai/v1/chat/completions": ("xai", "/v1/chat/completions"),
        }
        request_path, _, query = self.path.partition("?")
        if not supported_query(query):
            self.send_body(400, b'{"error":"Unsupported query parameters; no request forwarded"}')
            return
        route = routes.get(request_path)
        if not route:
            self.send_body(
                400, b'{"error":"Unsupported endpoint; no request forwarded"}'
            )
            return
        agent, path = route
        if agent in API_AUTH_PREFIXES and agent not in self.server.api_upstreams:
            self.send_body(
                400,
                b'{"error":"API mode is not enabled for this gateway instance"}',
            )
            return
        if agent not in self.server.upstreams:
            self.send_body(
                400, b'{"error":"Provider is not enabled for this gateway instance"}'
            )
            return
        auth = self.headers.get("Authorization", "")
        if agent in API_AUTH_PREFIXES:
            # Explicit API mode: the caller's own API key is forwarded to the
            # fixed origin. Subscription tokens are not accepted and no
            # automatic fallback to or from subscription auth exists.
            valid_auth = auth.startswith(API_AUTH_PREFIXES[agent])
        else:
            # Subscription-only boundary: never silently switch to paid API keys.
            valid_auth = (
                auth.startswith("Bearer sk-ant-oat")
                if agent == "claude"
                else auth.startswith("Bearer eyJ")
            )
        if not valid_auth or self.headers.get("x-api-key"):
            self.send_body(
                401,
                b'{"error":"xAI API key required; subscription credentials refused"}'
                if agent in API_AUTH_PREFIXES
                else b'{"error":"Existing subscription OAuth login required; API keys refused"}',
            )
            return
        if not self.server.try_admit(agent):
            self.response_headers = {"Retry-After": "1"}
            self.send_body(503 if self.server.closing else 429,
                           b'{"error":"Gateway inference capacity unavailable; retry later"}')
            return
        meta = self.audit_metadata
        if meta is not None:
            meta["credential_ref"] = anonymous_ref(self.server.token, "credential", auth)
            if agent == "codex":
                meta["account_ref"] = anonymous_ref(
                    self.server.token, "account", self.headers.get("chatgpt-account-id", ""),
                )
            source = self.headers.get("X-SecureMCP-Agent")
            if agent == "xai" and source in {"Grok Build", "Antigravity SDK"}:
                meta["agent"] = source
        try:
            if self.headers.get("Transfer-Encoding") or self.headers.get(
                "Content-Encoding"
            ):
                raise ValueError("Encoded/chunked requests unsupported.")
            length = int(self.headers.get("Content-Length", "0"))
            if not 0 < length <= LIMIT:
                raise ValueError("Request size limit exceeded.")
            raw = self.rfile.read(length)
            if meta is not None:
                meta["input_bytes"] = len(raw)
            payload = json.loads(raw)
            if not isinstance(payload, dict):
                raise ValueError("Request must be a JSON object.")
            if meta is not None and isinstance(payload.get("model"), str):
                model = payload["model"]
                if re.fullmatch(r"[A-Za-z0-9_.:/-]{1,128}", model):
                    meta["model"] = model
            # Refresh stays CLI-owned; changing bearer tokens must not change aliases.
            session = self.server.get_session(agent)
            with session.lock:
                dialect = (
                    "chat_completions"
                    if path.endswith("/chat/completions")
                    else "responses"
                    if agent in API_AUTH_PREFIXES
                    else None
                )
                before = len(session.session.forward_store)
                masked = session.request(payload, dialect=dialect)
                if meta is not None:
                    meta["new_aliases"] = max(0, len(session.session.forward_store) - before)
                session.active_requests += 1
                session.session.touch()
            try:
                headers = {
                    "Content-Type": "application/json",
                    "Authorization": auth,
                    "Accept": "text/event-stream"
                    if masked.get("stream")
                    else "application/json",
                }
                for key in (
                    ()
                    if agent in API_AUTH_PREFIXES
                    else (
                        "anthropic-version",
                        "anthropic-beta",
                        "chatgpt-account-id",
                        "OpenAI-Beta",
                        "User-Agent",
                        "originator",
                        "session_id",
                        "x-codex-beta-features",
                    )
                ):
                    if self.headers.get(key):
                        headers[key] = self.headers[key]
                masked_data = json.dumps(masked, ensure_ascii=False).encode()
                if meta is not None:
                    meta["masked_bytes"] = len(masked_data)
                request = urllib.request.Request(
                    self.server.upstreams[agent] + path + ("?" + query if query else ""),
                    data=masked_data,
                    headers=headers,
                )
                # Disable redirects and environment proxies: credentials stay at the fixed origin.
                opener = urllib.request.build_opener(
                    urllib.request.ProxyHandler({}), NoRedirect()
                )
                try:
                    if meta is not None:
                        meta["upstream_attempted"] = 1
                        meta["outcome"] = "transport_error"
                    upstream_response = opener.open(request, timeout=180)
                except urllib.error.HTTPError:
                    raise
                except (OSError, http.client.HTTPException) as exc:
                    reason = getattr(exc, "reason", exc)
                    status = 504 if isinstance(reason, (TimeoutError, socket.timeout)) else 502
                    self.send_body(status, b'{"error":"Upstream transport unavailable"}')
                    return
                with upstream_response as upstream:
                    self.capture_response_headers(upstream.headers)
                    try:
                        body = upstream.read(LIMIT + 1)
                    except (OSError, http.client.HTTPException) as exc:
                        reason = getattr(exc, "reason", exc)
                        status = 504 if isinstance(reason, TimeoutError) else 502
                        self.send_body(status, b'{"error":"Upstream transport unavailable"}')
                        return
                    if len(body) > LIMIT:
                        self.send_body(502, b'{"error":"Upstream response size limit exceeded"}')
                        return
                    content_type = upstream.headers.get(
                        "Content-Type", "application/json"
                    )
                    if masked.get("stream") and body.startswith(
                        (b"event:", b"data:", b":")
                    ):
                        content_type = "text/event-stream"
                    with session.lock:
                        if meta is not None:
                            meta["outcome"] = "restore_error"
                        try:
                            restored = session.response(body, content_type, dialect=dialect)
                        except (ValueError, TypeError, AttributeError, KeyError, RecursionError):
                            self.send_body(502, b'{"error":"Upstream response could not be safely restored"}')
                            return
                        self.server.save(agent, session)
                self.send_body(200, restored, content_type)
            finally:
                with session.lock:
                    session.active_requests -= 1
        except urllib.error.HTTPError as exc:
            if meta is not None:
                meta["outcome"] = "upstream_rejected"
            self.capture_response_headers(exc.headers)
            status, body = sanitized_upstream_error(exc)
            self.send_body(status, body)
        except (
            ValueError,
            TypeError,
            KeyError,
            OSError,
            RecursionError,
            http.client.HTTPException,
        ):
            self.send_body(
                400,
                b'{"error":"Privacy gateway could not safely process this request; nothing bypassed masking"}',
            )
        finally:
            self.server.release_admission(agent)


def supported_query(query):
    if not query:
        return True
    if len(query) > 256:
        return False
    try:
        pairs = urllib.parse.parse_qsl(query, keep_blank_values=True, strict_parsing=True)
    except ValueError:
        return False
    if len({key for key, _ in pairs}) != len(pairs):
        return False
    return all(
        (key in {"beta", "stream"} and value in {"true", "false"})
        or (key == "client_version" and re.fullmatch(r"[0-9]{1,4}(?:\.[0-9]{1,4}){0,3}", value))
        or (key == "api-version" and re.fullmatch(r"[0-9]{4}-[0-9]{2}-[0-9]{2}", value))
        for key, value in pairs
    )


PUBLIC_ERROR_TYPES = {
    "invalid_request_error",
    "authentication_error",
    "permission_error",
    "not_found_error",
    "rate_limit_error",
    "api_error",
    "overloaded_error",
}
PUBLIC_ERROR_CODES = {
    "context_length_exceeded",
    "rate_limit_exceeded",
    "model_not_found",
    "invalid_api_key",
    "insufficient_quota",
    "server_error",
    "invalid_request",
    "request_too_large",
    "overloaded_error",
}
UPSTREAM_ERROR_STATUSES = {
    400,
    401,
    403,
    404,
    408,
    413,
    422,
    429,
    500,
    502,
    503,
    504,
    529,
}


def sanitized_upstream_error(exc):
    status = exc.code if exc.code in UPSTREAM_ERROR_STATUSES else 502
    error = {"message": "Upstream rejected the request."}
    try:
        body = exc.read(LIMIT + 1)
        if len(body) <= LIMIT:
            payload = json.loads(body)
            upstream = payload.get("error", {}) if isinstance(payload, dict) else {}
            if isinstance(upstream, dict):
                # Anthropic supplies this condition as a 400 message, without
                # a machine-readable code. Classify only the fixed prefix;
                # never echo token counts, filenames or other upstream text.
                message = upstream.get("message")
                if (
                    status == 400
                    and upstream.get("type") == "invalid_request_error"
                    and isinstance(message, str)
                    and re.match(r"\Aprompt is too long(?:\s*:|\s*;|\s*$)", message, re.IGNORECASE)
                ):
                    error["code"] = "context_length_exceeded"
                for field, allowed in (
                    ("type", PUBLIC_ERROR_TYPES),
                    ("code", PUBLIC_ERROR_CODES),
                ):
                    value = upstream.get(field)
                    if isinstance(value, str) and value in allowed:
                        error[field] = value
    except (ValueError, OSError, http.client.HTTPException):
        pass
    finally:
        exc.close()
    if status == 413 or error.get("code") == "context_length_exceeded":
        error["message"] = (
            "Prompt is too long; reduce context or compact the conversation."
        )
    return status, json.dumps({"error": error}).encode()


class NoRedirect(urllib.request.HTTPRedirectHandler):
    def redirect_request(self, req, fp, code, msg, headers, newurl):
        return None
