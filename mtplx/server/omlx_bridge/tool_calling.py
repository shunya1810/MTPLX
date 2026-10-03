# SPDX-License-Identifier: Apache-2.0
"""Tool-call parsing and stream filtering adapted from oMLX.

Source inspiration: oMLX ``omlx/api/tool_calling.py`` on origin/main,
Apache-2.0. MTPLX intentionally uses this module as a protocol adapter, not as
a model babysitter: visible text is preserved, raw control markup is filtered,
and valid tool calls are parsed at completion.
"""

from __future__ import annotations

import ast
import json
import re
import uuid
from dataclasses import dataclass
from typing import Any


# LFM-family (lfm2/lfm2_moe/lfm2.5) tool envelope: special tokens survive the
# mlx-lm detokenizer as literal text, wrapping a python-call list such as
# [get_weather(city='Paris'), get_time(tz={"name": "CET"})].
PYTHONIC_TOOL_CALL_START = "<|tool_call_start|>"
PYTHONIC_TOOL_CALL_END = "<|tool_call_end|>"
_PYTHONIC_ENVELOPE_RE = re.compile(
    re.escape(PYTHONIC_TOOL_CALL_START)
    + r"(.*?)"
    + re.escape(PYTHONIC_TOOL_CALL_END),
    re.DOTALL,
)


@dataclass(frozen=True)
class ToolCallExtraction:
    cleaned_text: str
    tool_calls: list[dict[str, Any]] | None
    cleaned_thinking: str
    parser_source: str = "none"
    status: str = "no_tool"
    malformed_reason: str | None = None
    raw_tool_markup_suppressed: bool = False


def _serialize_tool_call_arguments(arguments: Any) -> str:
    if isinstance(arguments, dict):
        return json.dumps(
            _order_tool_arguments_for_client_display("", arguments),
            ensure_ascii=False,
            separators=(",", ":"),
        )
    if isinstance(arguments, str):
        try:
            parsed = json.loads(arguments)
        except (TypeError, ValueError):
            parsed = None
        if isinstance(parsed, dict):
            return json.dumps(parsed, ensure_ascii=False, separators=(",", ":"))
    return "{}"


_TOOL_ARGUMENT_PRIMARY_ORDER: dict[str, tuple[str, ...]] = {
    "read": ("filePath", "path", "offset", "limit"),
    "grep": ("pattern", "path", "include", "limit"),
    "glob": ("pattern", "path"),
    "bash": ("command", "description", "timeout"),
    "write": ("filePath", "path", "content"),
    "edit": ("filePath", "path", "oldString", "newString", "replaceAll"),
    "webfetch": ("url", "format", "timeout"),
    "skill": ("name",),
    "question": ("questions",),
}


def _order_tool_arguments_for_client_display(
    tool_name: str,
    arguments: dict[str, Any],
) -> dict[str, Any]:
    """Return stable argument order so clients do not lead with display noise.

    OpenCode renders tool argument values in JSON insertion order. Qwen can emit
    optional knobs such as ``limit`` before the useful target path, producing
    transcript rows that start with a bare ``100``. This preserves every
    argument and only moves the user-facing identifiers first.
    """

    if not arguments:
        return arguments
    order = _TOOL_ARGUMENT_PRIMARY_ORDER.get(str(tool_name or "").strip().lower())
    if not order:
        return arguments
    ordered: dict[str, Any] = {}
    for key in order:
        if key in arguments:
            ordered[key] = arguments[key]
    for key, value in arguments.items():
        if key not in ordered:
            ordered[key] = value
    return ordered


def _tool_call(name: str, arguments: Any) -> dict[str, Any]:
    if isinstance(arguments, dict):
        arguments = _order_tool_arguments_for_client_display(str(name), arguments)
    return {
        "id": f"call_{uuid.uuid4().hex[:8]}",
        "type": "function",
        "function": {
            "name": str(name),
            "arguments": _serialize_tool_call_arguments(arguments),
        },
    }


def _coerce_json_tool_payload(parsed: Any) -> dict[str, Any] | None:
    if isinstance(parsed, list):
        for item in parsed:
            coerced = _coerce_json_tool_payload(item)
            if coerced is not None:
                return coerced
        return None
    if not isinstance(parsed, dict):
        return None
    function = parsed.get("function")
    if isinstance(function, dict):
        name = function.get("name") or function.get("tool") or function.get("function")
        arguments = (
            function.get("arguments")
            if "arguments" in function
            else function.get("args", function.get("parameters", {}))
        )
        if name:
            return _tool_call(str(name), arguments)
    name = (
        parsed.get("name")
        or parsed.get("tool")
        or parsed.get("function")
        or parsed.get("call")
    )
    if not name:
        return None
    arguments = parsed.get("arguments", parsed.get("args", parsed.get("parameters", {})))
    return _tool_call(str(name), arguments)


def _parse_json_tool_payload(content: str) -> dict[str, Any] | None:
    try:
        parsed = json.loads(content)
    except (TypeError, ValueError):
        return None
    return _coerce_json_tool_payload(parsed)


def _parse_bare_tool_payload(content: str) -> dict[str, Any] | None:
    stripped = content.strip()
    match = re.match(
        r"^([A-Za-z_][\w.-]*)\s*(?:\((.*)\)|:\s*(\{.*\})|(\{.*\}))\s*$",
        stripped,
        re.DOTALL,
    )
    if not match:
        return None
    name = match.group(1)
    raw_args = next((group for group in match.groups()[1:] if group), "{}")
    try:
        arguments = json.loads(raw_args)
    except (TypeError, ValueError):
        arguments = {"_raw": raw_args}
    return _tool_call(name, arguments)


def _qwen_xml_param(raw: str) -> Any:
    """A Qwen XML parameter value with only its framing newlines removed.

    The chat template renders '<parameter=NAME>\n' + value + '\n</parameter>'.
    Stripping every surrounding whitespace (as before) changed the value: a
    file's trailing newline or its first line's indentation was lost, and the
    re-rendered history no longer matched what the model generated, so the
    session bank refused the turn's snapshot (an omp write of a 74K-token
    thinking turn, 2026-10-04: the next call prefilled 74K tokens again).
    JSON values (numbers, booleans, objects) still parse from the trimmed text.
    """

    value = raw[1:] if raw.startswith("\n") else raw
    value = value[:-1] if value.endswith("\n") else value
    stripped = value.strip()
    if stripped[:1] in {"{", "[", '"'} or stripped in {"true", "false", "null"} or _looks_numeric(stripped):
        try:
            return json.loads(stripped)
        except (TypeError, ValueError):
            pass
    # Single-line values (paths, commands) stay trimmed, as before.
    return value if "\n" in stripped else stripped


def _looks_numeric(text: str) -> bool:
    try:
        float(text)
    except ValueError:
        return False
    return bool(text) and text[0] in "-0123456789"


def _parse_xml_tool_calls(text: str) -> tuple[str, list[dict[str, Any]] | None, str | None]:
    calls: list[dict[str, Any]] = []
    malformed_reason: str | None = None
    for match in re.findall(r"<tool_call>\s*(.*?)\s*</tool_call>", text, re.DOTALL):
        content = match.strip()
        if parsed := _parse_json_tool_payload(content):
            calls.append(parsed)
            continue
        if parsed := _parse_bare_tool_payload(content):
            calls.append(parsed)
            continue
        func_match = re.match(
            r"<function=([^>\s]+)>\s*(.*?)\s*</function>",
            content,
            re.DOTALL,
        )
        if func_match is None:
            func_match = re.match(
                r'<function\s+name="([^"]+)">\s*(.*?)\s*</function>',
                content,
                re.DOTALL,
            )
        if func_match:
            name = func_match.group(1)
            params = {}
            param_patterns = (
                # Qwen XML: the template writes '<parameter=NAME>\n' + value
                # + '\n</parameter>', so exactly one newline on each side is
                # framing and everything else is the value (_qwen_xml_param).
                (r"<parameter=([^>\s]+)>(.*?)</parameter>", True),
                (r'<parameter\s+name="([^"]+)">\s*(.*?)\s*</parameter>', False),
            )
            for pattern, qwen_xml in param_patterns:
                for param in re.finditer(pattern, func_match.group(2), re.DOTALL):
                    key = param.group(1)
                    if qwen_xml:
                        params[key] = _qwen_xml_param(param.group(2))
                        continue
                    value = param.group(2).strip()
                    try:
                        params[key] = json.loads(value)
                    except (TypeError, ValueError):
                        params[key] = value
            if not params:
                body = func_match.group(2).strip()
                if body:
                    # #170: a pure JSON-object body inside the envelope is the
                    # arguments payload (same contract as the strict parsers).
                    parsed_body = None
                    if body.startswith("{"):
                        try:
                            parsed_body = json.loads(body)
                        except (TypeError, ValueError):
                            parsed_body = None
                    if isinstance(parsed_body, dict):
                        params = parsed_body
                    else:
                        # Never fabricate a {}-arguments call out of a body the
                        # parser could not read — that silent empty call is the
                        # measured #170 client shape. The turn stays visible
                        # content instead.
                        malformed_reason = (
                            f"tool '{name}' contains unwrapped parameter text"
                        )
                        calls = []
                        break
            calls.append(_tool_call(name, params))
            continue
        invoke_match = re.match(
            r'<invoke\s+name="([^"]+)">\s*(.*?)\s*</invoke>',
            content,
            re.DOTALL,
        )
        if invoke_match:
            name = invoke_match.group(1)
            params = {}
            for param in re.finditer(
                r'<parameter\s+name="([^"]+)">\s*(.*?)\s*</parameter>',
                invoke_match.group(2),
                re.DOTALL,
            ):
                key = param.group(1)
                value = param.group(2).strip()
                try:
                    params[key] = json.loads(value)
                except (TypeError, ValueError):
                    params[key] = value
            if not params and invoke_match.group(2).strip():
                malformed_reason = (
                    f"tool '{name}' contains unwrapped parameter text"
                )
                calls = []
                break
            calls.append(_tool_call(name, params))
            continue
        # Poolside dialect: `name<arg_key>k</arg_key><arg_value>v</arg_value>...`
        # (the Laguna family's native emission; same contract as the strict
        # parser in openai.py — every non-pair byte after the name is residue
        # and marks the call malformed rather than silently dropping args).
        poolside_match = re.match(r"\s*([A-Za-z_][\w.-]*)", content)
        if poolside_match:
            poolside_name = poolside_match.group(1)
            body = content[poolside_match.end():]
            pairs = list(
                re.finditer(
                    r"<arg_key>\s*(.*?)\s*</arg_key>\s*<arg_value>\s*(.*?)\s*</arg_value>",
                    body,
                    re.DOTALL,
                )
            )
            if pairs:
                params = {}
                residue_parts = []
                cursor = 0
                valid = True
                for pair in pairs:
                    key = pair.group(1).strip()
                    if not key or key in params:
                        valid = False
                        break
                    value = pair.group(2).strip()
                    try:
                        params[key] = json.loads(value)
                    except (TypeError, ValueError):
                        params[key] = value
                    residue_parts.append(body[cursor:pair.start()])
                    cursor = pair.end()
                residue_parts.append(body[cursor:])
                if valid and not "".join(residue_parts).strip():
                    calls.append(_tool_call(poolside_name, params))
                    continue
                malformed_reason = (
                    f"tool '{poolside_name}' contains malformed Poolside arguments"
                )
                calls = []
                break
        malformed_reason = "unrecognized <tool_call> payload"
    if not calls:
        return text, None, malformed_reason
    cleaned = re.sub(r"<tool_call>.*?</tool_call>", "", text, flags=re.DOTALL).strip()
    return cleaned, calls, None


def _parse_namespaced_tool_calls(text: str) -> tuple[str, list[dict[str, Any]] | None]:
    calls: list[dict[str, Any]] = []
    pattern = r"<([A-Za-z_][\w.-]*):tool_call>\s*(.*?)\s*</\1:tool_call>"
    for _namespace, content in re.findall(pattern, text, re.DOTALL):
        for invoke in re.finditer(
            r'<invoke\s+name="([^"]+)">\s*(.*?)\s*</invoke>',
            content,
            re.DOTALL,
        ):
            params = {}
            for param in re.finditer(
                r'<parameter\s+name="([^"]+)">\s*(.*?)\s*</parameter>',
                invoke.group(2),
                re.DOTALL,
            ):
                value = param.group(2).strip()
                try:
                    params[param.group(1)] = json.loads(value)
                except (TypeError, ValueError):
                    params[param.group(1)] = value
            if not params and invoke.group(2).strip():
                # No fabricated {}-arguments calls from unread bodies (#170).
                continue
            calls.append(_tool_call(invoke.group(1), params))
    if not calls:
        return text, None
    cleaned = re.sub(pattern, "", text, flags=re.DOTALL).strip()
    return cleaned, calls


_SUFFIXED_TOOL_CALL_RE = re.compile(
    r"<tool_call(?P<suffix>:[A-Za-z_][\w.-]*)>"
    r"\s*(?P<body>.*?)\s*"
    r"</tool_call(?P=suffix)>",
    re.DOTALL,
)
_SUFFIXED_TOOL_CALLS_RE = re.compile(
    r"<tool_calls(?P<suffix>:[A-Za-z_][\w.-]*)>"
    r"\s*(?P<body>.*?)\s*"
    r"</tool_calls(?P=suffix)>",
    re.DOTALL,
)


def _tool_parameter_schema(
    tools: list[dict[str, Any]] | None,
    *,
    tool_name: str,
    parameter_name: str,
) -> dict[str, Any] | None:
    for tool in tools or []:
        function = tool.get("function") if isinstance(tool, dict) else None
        if not isinstance(function, dict):
            continue
        if str(function.get("name") or "") != tool_name:
            continue
        parameters = function.get("parameters")
        properties = (
            parameters.get("properties") if isinstance(parameters, dict) else None
        )
        schema = (
            properties.get(parameter_name) if isinstance(properties, dict) else None
        )
        return schema if isinstance(schema, dict) else None
    return None


def _decode_suffixed_argument(
    value: str,
    *,
    schema: dict[str, Any] | None,
) -> Any:
    text = value.strip()
    schema_type = schema.get("type") if isinstance(schema, dict) else None
    schema_types = (
        {schema_type}
        if isinstance(schema_type, str)
        else {str(item) for item in schema_type}
        if isinstance(schema_type, list)
        else set()
    )
    if schema_types and schema_types <= {"string", "null"}:
        return text
    try:
        return json.loads(text)
    except (TypeError, ValueError):
        return text


def _parse_suffixed_native_tool_calls(
    text: str,
    tools: list[dict[str, Any]] | None,
) -> tuple[str, list[dict[str, Any]] | None, str | None]:
    """Parse Hy3-style suffix-token tool calls.

    Hy3's official tokenizer uses special tokens such as
    ``<tool_call:opensource>`` and an argument-key/value protocol instead of
    Qwen's ``<function=>`` XML. Treat the suffix as an opaque protocol
    namespace so future tokenizer revisions using the same grammar work
    without a model-name check.
    """

    calls: list[dict[str, Any]] = []
    malformed_reason: str | None = None
    matches = list(_SUFFIXED_TOOL_CALL_RE.finditer(text or ""))
    for index, match in enumerate(matches):
        suffix = match.group("suffix")
        body = match.group("body").strip()
        separator = f"<tool_sep{suffix}>"
        if separator not in body:
            malformed_reason = (
                f"suffixed tool_call[{index}] is missing its tool separator"
            )
            calls = []
            break
        raw_name, raw_arguments = body.split(separator, 1)
        name = raw_name.strip()
        if not name:
            malformed_reason = f"suffixed tool_call[{index}] is missing a name"
            calls = []
            break

        key_open = re.escape(f"<arg_key{suffix}>")
        key_close = re.escape(f"</arg_key{suffix}>")
        value_open = re.escape(f"<arg_value{suffix}>")
        value_close = re.escape(f"</arg_value{suffix}>")
        argument_re = re.compile(
            key_open
            + r"\s*(?P<key>.*?)\s*"
            + key_close
            + r"\s*"
            + value_open
            + r"\s*(?P<value>.*?)\s*"
            + value_close,
            re.DOTALL,
        )
        arguments: dict[str, Any] = {}
        consumed: list[tuple[int, int]] = []
        for argument in argument_re.finditer(raw_arguments):
            key = argument.group("key").strip()
            if not key:
                malformed_reason = (
                    f"suffixed tool_call[{index}] contains an empty argument key"
                )
                calls = []
                break
            arguments[key] = _decode_suffixed_argument(
                argument.group("value"),
                schema=_tool_parameter_schema(
                    tools,
                    tool_name=name,
                    parameter_name=key,
                ),
            )
            consumed.append(argument.span())
        if malformed_reason:
            break

        residue_parts: list[str] = []
        cursor = 0
        for start, end in consumed:
            residue_parts.append(raw_arguments[cursor:start])
            cursor = end
        residue_parts.append(raw_arguments[cursor:])
        if "".join(residue_parts).strip():
            malformed_reason = (
                f"suffixed tool_call[{index}] contains text outside arguments"
            )
            calls = []
            break
        calls.append(_tool_call(name, arguments))

    if not calls:
        return text, None, malformed_reason
    calls = _filter_known_tools(calls, tools) or []
    if not calls:
        return text, None, "suffixed tool calls named no declared tool"

    cleaned = _SUFFIXED_TOOL_CALLS_RE.sub("", text or "")
    cleaned = _SUFFIXED_TOOL_CALL_RE.sub("", cleaned)
    return cleaned.strip(), calls, None


def _parse_bracket_tool_calls(text: str) -> tuple[str, list[dict[str, Any]] | None]:
    calls: list[dict[str, Any]] = []
    pattern = r"\[(?:Calling tool|Tool call):\s*([A-Za-z_][\w.-]*)(?:\(({.*?})\))?\]"
    for name, args_text in re.findall(pattern, text, re.DOTALL):
        arguments: Any = {}
        if args_text:
            try:
                arguments = json.loads(args_text)
            except (TypeError, ValueError):
                arguments = {}
        calls.append(_tool_call(name, arguments))
    if not calls:
        return text, None
    return re.sub(pattern, "", text, flags=re.DOTALL).strip(), calls


def _pythonic_literal(node: ast.expr) -> Any:
    """Evaluate a python-call argument node without executing anything.

    LFM templates render string values single-quoted, mappings via ``tojson``
    (so ``true``/``false``/``null`` appear as bare names inside dicts), and
    everything else through ``str()`` — which spells Python ``True``/``None``.
    Both spellings must decode; any non-literal expression is malformed.
    """

    if isinstance(node, ast.Constant):
        return node.value
    if isinstance(node, ast.Name):
        lowered = node.id.lower()
        if lowered in {"true", "false"}:
            return lowered == "true"
        if lowered in {"null", "none"}:
            return None
        raise ValueError(f"unsupported bare name {node.id!r}")
    if isinstance(node, ast.Dict):
        result: dict[Any, Any] = {}
        for key_node, value_node in zip(node.keys, node.values):
            if key_node is None:
                raise ValueError("dict unpacking is not a literal")
            result[_pythonic_literal(key_node)] = _pythonic_literal(value_node)
        return result
    if isinstance(node, (ast.List, ast.Tuple, ast.Set)):
        return [_pythonic_literal(element) for element in node.elts]
    if (
        isinstance(node, ast.UnaryOp)
        and isinstance(node.op, ast.USub)
        and isinstance(node.operand, ast.Constant)
        and isinstance(node.operand.value, (int, float))
    ):
        return -node.operand.value
    raise ValueError(f"unsupported argument expression {ast.dump(node)[:80]}")


def _pythonic_call_name(func: ast.expr) -> str | None:
    if isinstance(func, ast.Name):
        return func.id
    if isinstance(func, ast.Attribute):
        parent = _pythonic_call_name(func.value)
        return f"{parent}.{func.attr}" if parent else None
    return None


def _sole_tool_parameter_name(
    tools: list[dict[str, Any]] | None,
    tool_name: str,
) -> str | None:
    for tool in tools or []:
        function = tool.get("function") if isinstance(tool, dict) else None
        candidate = function if isinstance(function, dict) else tool
        if not isinstance(candidate, dict):
            continue
        if str(candidate.get("name")) != tool_name:
            continue
        parameters = candidate.get("parameters")
        properties = (
            parameters.get("properties") if isinstance(parameters, dict) else None
        )
        if isinstance(properties, dict) and len(properties) == 1:
            return next(iter(properties))
        return None
    return None


def _parse_pythonic_marker_tool_calls(
    text: str,
    tools: list[dict[str, Any]] | None,
) -> tuple[str, list[dict[str, Any]] | None, str | None]:
    calls: list[dict[str, Any]] = []
    malformed: str | None = None
    envelopes = _PYTHONIC_ENVELOPE_RE.findall(text or "")
    if not envelopes:
        return text, None, "unclosed pythonic tool call envelope"
    for index, body in enumerate(envelopes):
        body = body.strip()
        if not body:
            malformed = f"pythonic tool_call[{index}] is empty"
            calls = []
            break
        try:
            tree = ast.parse(body, mode="eval")
        except SyntaxError:
            malformed = f"pythonic tool_call[{index}] is not a call expression"
            calls = []
            break
        nodes = (
            list(tree.body.elts)
            if isinstance(tree.body, (ast.List, ast.Tuple))
            else [tree.body]
        )
        for node in nodes:
            if not isinstance(node, ast.Call):
                malformed = f"pythonic tool_call[{index}] contains a non-call item"
                break
            name = _pythonic_call_name(node.func)
            if not name:
                malformed = f"pythonic tool_call[{index}] has an unreadable name"
                break
            arguments: dict[str, Any] = {}
            if node.args:
                # The template only renders keyword arguments; accept a single
                # positional only when the named tool declares exactly one
                # parameter, so the intent is unambiguous.
                sole = (
                    _sole_tool_parameter_name(tools, name)
                    if len(node.args) == 1 and not node.keywords
                    else None
                )
                if sole is None:
                    malformed = (
                        f"pythonic tool_call[{index}] uses positional arguments"
                    )
                    break
                try:
                    arguments[sole] = _pythonic_literal(node.args[0])
                except ValueError as exc:
                    malformed = f"pythonic tool_call[{index}]: {exc}"
                    break
            argument_error: str | None = None
            for keyword in node.keywords:
                if keyword.arg is None:
                    argument_error = (
                        f"pythonic tool_call[{index}] uses ** unpacking"
                    )
                    break
                try:
                    arguments[keyword.arg] = _pythonic_literal(keyword.value)
                except ValueError as exc:
                    argument_error = f"pythonic tool_call[{index}]: {exc}"
                    break
            if argument_error:
                malformed = argument_error
                break
            calls.append(_tool_call(name, arguments))
        if malformed:
            calls = []
            break
    if not calls:
        return text, None, malformed
    calls = _filter_known_tools(calls, tools) or []
    if not calls:
        return text, None, "pythonic tool calls named no declared tool"
    cleaned = _PYTHONIC_ENVELOPE_RE.sub("", text or "").strip()
    return cleaned, calls, None


def _allowed_tool_names(tools: list[dict[str, Any]] | None) -> set[str]:
    names: set[str] = set()
    for tool in tools or []:
        function = tool.get("function") if isinstance(tool, dict) else None
        if isinstance(function, dict) and function.get("name"):
            names.add(str(function["name"]))
        elif isinstance(tool, dict) and tool.get("name"):
            names.add(str(tool["name"]))
    return names


def _filter_known_tools(
    calls: list[dict[str, Any]] | None,
    tools: list[dict[str, Any]] | None,
) -> list[dict[str, Any]] | None:
    if not calls or not tools:
        return calls
    allowed = _allowed_tool_names(tools)
    filtered = [
        call
        for call in calls
        if call.get("function", {}).get("name") in allowed
    ]
    return filtered or None


def _function_body_is_blank(envelope: str) -> bool:
    """True when the tool envelope carries no payload beyond its tags.

    An empty ``<function=name></function>`` block is a legitimate no-argument
    call and must keep parsing to ``{}`` (the stream-level contract pinned by
    test_chat_stream_missing_required_tool_argument_still_emits_model_tool_call).
    A non-blank body that no parser could read must never become ``{}``.
    """
    inner = re.match(
        r"\s*<function(?:=[^>\s]+|\s+name=\"[^\"]+\")>\s*(.*?)\s*</function>\s*$",
        envelope.strip(),
        re.DOTALL,
    )
    if inner is None:
        return not envelope.strip()
    return not inner.group(1).strip()


def parse_tool_calls(
    text: str,
    tokenizer: Any | None,
    tools: list[dict[str, Any]] | None = None,
) -> ToolCallExtraction:
    cleaned_text = re.sub(r"<think>.*?</think>", "", text or "", flags=re.DOTALL)
    raw_markup = any(
        marker in (text or "")
        for marker in (
            "<tool_call",
            "</tool_call>",
            "[Calling tool:",
            "[Tool call:",
            PYTHONIC_TOOL_CALL_START,
        )
    )

    if re.search(r"<tool_calls?:[A-Za-z_][\w.-]*>", cleaned_text):
        cleaned, calls, malformed = _parse_suffixed_native_tool_calls(
            cleaned_text,
            tools,
        )
        if calls:
            return ToolCallExtraction(
                cleaned_text=cleaned,
                tool_calls=calls,
                cleaned_thinking="",
                parser_source="suffixed_native",
                status="parsed",
                raw_tool_markup_suppressed=True,
            )
        return ToolCallExtraction(
            cleaned_text=cleaned_text,
            tool_calls=None,
            cleaned_thinking="",
            parser_source="suffixed_native",
            status="malformed_as_content",
            malformed_reason=malformed or "unclosed or invalid suffixed tool call",
            raw_tool_markup_suppressed=False,
        )

    if tokenizer is not None and getattr(tokenizer, "has_tool_calling", False):
        start = getattr(tokenizer, "tool_call_start", None)
        end = getattr(tokenizer, "tool_call_end", None)
        parser = getattr(tokenizer, "tool_parser", None)
        if start and parser:
            matches: list[str] = []
            if end:
                matches = re.findall(
                    rf"{re.escape(start)}(.*?){re.escape(end)}",
                    text or "",
                    flags=re.DOTALL,
                )
            elif start in (text or ""):
                matches = [
                    part
                    for part in re.split(re.escape(start), text or "")[1:]
                    if part.strip()
                ]
            calls: list[dict[str, Any]] = []
            for match in matches:
                try:
                    parsed = parser(match.strip(), tools)
                except Exception:
                    parsed = None
                items = parsed if isinstance(parsed, list) else [parsed]
                for item in items:
                    if not isinstance(item, dict):
                        continue
                    name = item.get("name")
                    if not name:
                        continue
                    arguments = item.get("arguments", {})
                    if not arguments and match.strip():
                        # #170: the native tokenizer parser returns an empty
                        # arguments object for envelope bodies it cannot read
                        # (a JSON-object body inside <function=...> being the
                        # common case). Never fabricate a {}-arguments call —
                        # give our own envelope parser a second opinion and
                        # adopt its arguments, or skip the item entirely.
                        _cleaned, recovered, _reason = _parse_xml_tool_calls(
                            "<tool_call>" + match.strip() + "</tool_call>"
                        )
                        recovered_args = None
                        for candidate in recovered or []:
                            candidate_fn = candidate.get("function") or {}
                            if str(candidate_fn.get("name")) == str(name):
                                try:
                                    recovered_args = json.loads(
                                        candidate_fn.get("arguments") or "{}"
                                    )
                                except (TypeError, ValueError):
                                    recovered_args = None
                                break
                        if recovered_args:
                            arguments = recovered_args
                        elif not _function_body_is_blank(match):
                            continue
                    calls.append(_tool_call(str(name), arguments))
            calls = _filter_known_tools(calls, tools) or []
            if calls:
                if end:
                    cleaned = re.sub(
                        rf"{re.escape(start)}.*?{re.escape(end)}",
                        "",
                        cleaned_text,
                        flags=re.DOTALL,
                    ).strip()
                else:
                    cleaned = cleaned_text.split(start, 1)[0].strip()
                return ToolCallExtraction(
                    cleaned_text=cleaned,
                    tool_calls=calls,
                    cleaned_thinking="",
                    parser_source="native",
                    status="parsed",
                    raw_tool_markup_suppressed=raw_markup,
                )

    if PYTHONIC_TOOL_CALL_START in cleaned_text:
        # LFM-family envelope. Runs after the tokenizer-native path so a
        # tokenizer that declares its own protocol on these markers keeps
        # precedence; today mlx-lm exposes none for lfm2 checkpoints.
        cleaned, calls, malformed = _parse_pythonic_marker_tool_calls(
            cleaned_text,
            tools,
        )
        if calls:
            return ToolCallExtraction(
                cleaned_text=cleaned,
                tool_calls=calls,
                cleaned_thinking="",
                parser_source="pythonic_marker",
                status="parsed",
                raw_tool_markup_suppressed=True,
            )
        return ToolCallExtraction(
            cleaned_text=cleaned_text,
            tool_calls=None,
            cleaned_thinking="",
            parser_source="pythonic_marker",
            status="malformed_as_content",
            malformed_reason=malformed or "unclosed or invalid pythonic tool call",
            raw_tool_markup_suppressed=False,
        )

    if "<tool_call" in cleaned_text:
        cleaned, calls, malformed = _parse_xml_tool_calls(cleaned_text)
        filtered_calls = _filter_known_tools(calls, tools)
        if calls and not filtered_calls and tools:
            # OpenAI passes unknown-named calls through; the client owns the
            # rejection (and answers the model, letting it self-correct).
            # Degrading the whole turn to prose costs the agent a strike.
            filtered_calls = calls
        if filtered_calls:
            return ToolCallExtraction(
                cleaned_text=cleaned,
                tool_calls=filtered_calls,
                cleaned_thinking="",
                parser_source="qwen_xml",
                status="parsed",
                raw_tool_markup_suppressed=True,
            )
        return ToolCallExtraction(
            cleaned_text=cleaned_text,
            tool_calls=None,
            cleaned_thinking="",
            parser_source="qwen_xml",
            status="malformed_as_content",
            malformed_reason=malformed or "unclosed or invalid tool_call markup",
            raw_tool_markup_suppressed=False,
        )

    if re.search(r"<[A-Za-z_][\w.-]*:tool_call>", cleaned_text):
        cleaned, calls = _parse_namespaced_tool_calls(cleaned_text)
        calls = _filter_known_tools(calls, tools)
        if calls:
            return ToolCallExtraction(
                cleaned_text=cleaned,
                tool_calls=calls,
                cleaned_thinking="",
                parser_source="namespaced",
                status="parsed",
                raw_tool_markup_suppressed=True,
            )

    if "[Calling tool:" in cleaned_text or "[Tool call:" in cleaned_text:
        cleaned, calls = _parse_bracket_tool_calls(cleaned_text)
        calls = _filter_known_tools(calls, tools)
        if calls:
            return ToolCallExtraction(
                cleaned_text=cleaned,
                tool_calls=calls,
                cleaned_thinking="",
                parser_source="bracket",
                status="parsed",
                raw_tool_markup_suppressed=True,
            )

    return ToolCallExtraction(
        cleaned_text=cleaned_text,
        tool_calls=None,
        cleaned_thinking="",
        parser_source="none",
        status="no_tool",
        raw_tool_markup_suppressed=raw_markup,
    )


def sanitize_tool_call_markup(text: str, tokenizer: Any | None = None) -> str:
    if not text:
        return ""
    filtered = ToolCallStreamFilter(tokenizer)
    return filtered.feed(text) + filtered.finish()


def extract_tool_calls_with_thinking(
    thinking_content: str,
    regular_content: str,
    tokenizer: Any | None,
    tools: list[dict[str, Any]] | None = None,
) -> ToolCallExtraction:
    result = parse_tool_calls(regular_content, tokenizer, tools)
    cleaned_thinking = sanitize_tool_call_markup(thinking_content, tokenizer)
    calls = result.tool_calls
    status = result.status
    source = result.parser_source
    malformed = result.malformed_reason
    if not calls and thinking_content:
        thinking_result = parse_tool_calls(thinking_content, tokenizer, tools)
        if thinking_result.tool_calls and not regular_content.strip():
            calls = thinking_result.tool_calls
            source = thinking_result.parser_source
            status = thinking_result.status
        elif thinking_result.status == "malformed_as_content" and status == "no_tool":
            status = thinking_result.status
            malformed = thinking_result.malformed_reason
            source = thinking_result.parser_source
    return ToolCallExtraction(
        cleaned_text=result.cleaned_text,
        tool_calls=calls,
        cleaned_thinking=cleaned_thinking,
        parser_source=source,
        status=status,
        malformed_reason=malformed,
        raw_tool_markup_suppressed=(
            result.raw_tool_markup_suppressed or cleaned_thinking != thinking_content
        ),
    )


class ToolCallStreamFilter:
    """Suppress tool-control markup while preserving normal streamed text."""

    def __init__(self, tokenizer: Any | None = None) -> None:
        start = getattr(tokenizer, "tool_call_start", None) if tokenizer is not None else None
        end = getattr(tokenizer, "tool_call_end", None) if tokenizer is not None else None
        self._marker_pairs: list[tuple[str, str]] = [
            ("<tool_call>", "</tool_call>"),
            (PYTHONIC_TOOL_CALL_START, PYTHONIC_TOOL_CALL_END),
        ]
        self._suppress_after_markers: list[str] = []
        if start:
            if end:
                self._marker_pairs.insert(0, (str(start), str(end)))
            else:
                self._suppress_after_markers.append(str(start))
        self._namespaced_open_re = re.compile(r"<([A-Za-z_][\w.-]*):tool_call>")
        self._suffixed_calls_open_re = re.compile(
            r"<tool_calls(?P<suffix>:[A-Za-z_][\w.-]*)>"
        )
        self._suffixed_call_open_re = re.compile(
            r"<tool_call(?P<suffix>:[A-Za-z_][\w.-]*)>"
        )
        self._bracket_prefixes = ["[Calling tool:", "[Tool call:"]
        self._bracket_call_re = re.compile(
            r"^\[(?:Calling tool|Tool call):\s*([A-Za-z_][\w.-]*)(?:\(({.*?})\))?\]",
            re.DOTALL,
        )
        self._buffer = ""
        self._suppressing_until: str | None = None
        self._suppressing = False
        self.suppressed_markup = False

    def _find_start_envelope(self, text: str) -> tuple[int, int, str | None] | None:
        starts: list[tuple[int, int, str | None]] = []
        for marker, close in self._marker_pairs:
            index = text.find(marker)
            if index >= 0:
                starts.append((index, len(marker), close))
        if match := self._namespaced_open_re.search(text):
            namespace = match.group(1)
            starts.append((match.start(), len(match.group(0)), f"</{namespace}:tool_call>"))
        if match := self._suffixed_calls_open_re.search(text):
            suffix = match.group("suffix")
            starts.append(
                (
                    match.start(),
                    len(match.group(0)),
                    f"</tool_calls{suffix}>",
                )
            )
        if match := self._suffixed_call_open_re.search(text):
            suffix = match.group("suffix")
            starts.append(
                (
                    match.start(),
                    len(match.group(0)),
                    f"</tool_call{suffix}>",
                )
            )
        for prefix in self._bracket_prefixes:
            index = text.find(prefix)
            while index >= 0:
                candidate = text[index:]
                bracket = self._bracket_call_re.match(candidate)
                if bracket:
                    starts.append((index, bracket.end(), None))
                index = text.find(prefix, index + 1)
        for marker in self._suppress_after_markers:
            index = text.find(marker)
            if index >= 0:
                starts.append((index, len(text) - index, "__suppress_permanently__"))
        return min(starts, key=lambda item: item[0]) if starts else None

    @staticmethod
    def _partial_prefix_len(text: str, marker: str) -> int:
        max_len = min(len(text), len(marker) - 1)
        for size in range(max_len, 0, -1):
            if text.endswith(marker[:size]):
                return size
        return 0

    @staticmethod
    def _could_be_partial_namespaced_open(candidate: str) -> bool:
        if not candidate.startswith("<") or ">" in candidate:
            return False
        body = candidate[1:]
        if not body or body.startswith("/"):
            return bool(not body)
        if ":" not in body:
            return re.match(r"^[A-Za-z_][\w.-]*$", body) is not None
        namespace, suffix = body.split(":", 1)
        return bool(
            re.match(r"^[A-Za-z_][\w.-]*$", namespace)
            and "tool_call".startswith(suffix)
        )

    @staticmethod
    def _could_be_partial_suffixed_open(candidate: str) -> bool:
        if not candidate.startswith("<") or ">" in candidate:
            return False
        lowered = candidate.lower()
        return (
            "<tool_calls:".startswith(lowered)
            or "<tool_call:".startswith(lowered)
            or bool(re.match(r"^<tool_calls?:[A-Za-z_][\w.-]*$", candidate))
        )

    _BRACKET_CALL_HEAD_RE = re.compile(
        r"^\[(?:Calling tool|Tool call):\s*([A-Za-z_][\w.-]*)?(\()?"
    )

    @classmethod
    def _bracket_call_may_complete(cls, candidate: str) -> bool:
        """True while ``candidate`` (starting at a bracket prefix) is still a
        structurally consistent prefix of ``[Calling tool: name({...})]``.

        This is what bounds the hold: a real call is held whole until its
        ``]`` however long its JSON arguments run (a file body is
        legitimate), while prose that merely quotes the marker ("MTPLX
        prints [Calling tool: read_file when it starts a tool") is released
        at the first character that can no longer belong to a call. Without
        this test the hold was unbounded and finish() dropped the rest of
        the answer.
        """

        head = cls._BRACKET_CALL_HEAD_RE.match(candidate)
        if head is None:
            return False
        rest = candidate[head.end() :]
        if not rest:
            return True
        if not head.group(1) or not head.group(2):
            # Text right after the prefix that is not a name, or text after
            # the name that is not "(": a complete "[...: name]" would already
            # have been consumed, so this is prose.
            return False
        if rest[0] != "{":
            return False
        end = cls._balanced_json_object_end(rest)
        if end is None:
            return True
        return re.fullmatch(r"\)?\]?", rest[end:]) is not None

    @staticmethod
    def _balanced_json_object_end(text: str) -> int | None:
        """Index just past the object that opens at ``text[0]``, or None if
        the object is still open (string- and escape-aware)."""

        depth = 0
        in_string = False
        escaped = False
        for index, char in enumerate(text):
            if in_string:
                if escaped:
                    escaped = False
                elif char == "\\":
                    escaped = True
                elif char == '"':
                    in_string = False
            elif char == '"':
                in_string = True
            elif char == "{":
                depth += 1
            elif char == "}":
                depth -= 1
                if depth == 0:
                    return index + 1
        return None

    def _partial_suffix_len(self, text: str) -> int:
        keep = 0
        for marker, _close in self._marker_pairs:
            keep = max(keep, self._partial_prefix_len(text, marker))
        for marker in self._suppress_after_markers:
            keep = max(keep, self._partial_prefix_len(text, marker))
        if (last_lt := text.rfind("<")) >= 0:
            candidate = text[last_lt:]
            if self._could_be_partial_namespaced_open(
                candidate
            ) or self._could_be_partial_suffixed_open(candidate):
                keep = max(keep, len(candidate))
        for prefix in self._bracket_prefixes:
            keep = max(keep, self._partial_prefix_len(text, prefix))
            index = text.rfind(prefix)
            if index >= 0 and self._bracket_call_may_complete(text[index:]):
                return max(keep, len(text) - index)
        return min(keep, 128)

    def _should_drop_tail_at_finish(self, tail: str) -> bool:
        if not tail:
            return False
        for marker, _close in self._marker_pairs:
            if marker.startswith(tail):
                return True
        for prefix in self._bracket_prefixes:
            # An unclosed call-shaped block stays suppressed (drift dialect
            # never reaches the transcript); a bracket tail that stopped
            # being a possible call is the answer's own words and is kept.
            if tail.startswith(prefix):
                return self._bracket_call_may_complete(tail)
        return tail.startswith("<") and ">" not in tail and ":" in tail

    def feed(self, text: str) -> str:
        if self._suppressing or not text:
            return ""
        self._buffer += text
        out: list[str] = []
        while self._buffer:
            if self._suppressing_until == "__suppress_permanently__":
                self.suppressed_markup = True
                self._suppressing = True
                self._suppressing_until = None
                self._buffer = ""
                break
            if self._suppressing_until is not None:
                end_index = self._buffer.find(self._suppressing_until)
                if end_index < 0:
                    keep = self._partial_prefix_len(self._buffer, self._suppressing_until)
                    self._buffer = self._buffer[-keep:] if keep else ""
                    break
                self.suppressed_markup = True
                self._buffer = self._buffer[end_index + len(self._suppressing_until) :]
                self._suppressing_until = None
                continue
            start = self._find_start_envelope(self._buffer)
            if start:
                index, consume_len, close_marker = start
                if index > 0:
                    out.append(self._buffer[:index])
                self.suppressed_markup = True
                self._buffer = self._buffer[index + consume_len :]
                if close_marker is not None:
                    self._suppressing_until = close_marker
                continue
            keep = self._partial_suffix_len(self._buffer)
            if keep == 0:
                out.append(self._buffer)
                self._buffer = ""
                break
            if len(self._buffer) > keep:
                out.append(self._buffer[:-keep])
                self._buffer = self._buffer[-keep:]
            break
        return "".join(out)

    def finish(self) -> str:
        if self._suppressing or self._suppressing_until is not None:
            self.suppressed_markup = True
            self._buffer = ""
            self._suppressing_until = None
            return ""
        keep = self._partial_suffix_len(self._buffer)
        if keep >= len(self._buffer):
            tail = self._buffer
            self._buffer = ""
            if self._should_drop_tail_at_finish(tail):
                self.suppressed_markup = True
                return ""
            return tail
        text = self._buffer[:-keep] if keep else self._buffer
        self._buffer = ""
        return text
