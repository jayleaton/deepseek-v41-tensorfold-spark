"""DeepSeek-V4.1 chat-encoding goldens: many conversations rendered by the Python engine's ``encoding.encode`` (the
serving encoder, TensorFold's ``families/deepseek_v41/cuda/encoding.py``) and, where it accepts them, by the
release ``chat_template.jinja`` (rendered as Hugging Face's ``apply_chat_template`` does). Effort names are the
Python app's (``app.py`` ``FIELD_EFFORTS``: medium 75; the release template's medium is 62); the "effort_field"
cases resolve a request's ``reasoning_effort`` with the app's own ``options``.

    python -I gen_template.py ENCODING_PY MODEL_DIR OUT.jsonl [--cases N] [--seed S]

Each line: {"messages", "tools", "thinking", "budget", "drop_thinking", "response_format", "generation",
"image_text", "expected" (encode's text, or null when it refuses), "error", "jinja" (the template's text, or null),
and for effort cases "effort_field" (the request's value), "default_thinking"}.
"""

from __future__ import annotations

import argparse
import copy
import importlib.util
import json
import random
import sys
from pathlib import Path

IMAGE_TEXT = "[image omitted: the model cannot see this image.]"

TOOLS = [
    {"type": "function", "function": {"name": "get_weather", "description": "Get the weather for a city",
                                      "parameters": {"type": "object", "properties": {
                                          "city": {"type": "string", "description": "City name"},
                                          "days": {"type": "integer", "minimum": 1, "maximum": 14},
                                          "unit": {"type": "string", "enum": ["celsius", "fahrenheit"]}},
                                          "required": ["city"]}}},
    {"type": "function", "function": {"name": "search", "description": "Search the web — 搜索网页",
                                      "parameters": {"type": "object", "properties": {
                                          "query": {"type": "string"}, "top_k": {"type": "number", "default": 2.5},
                                          "filters": {"type": "object", "properties": {"lang": {"type": ["string", "null"]}}},
                                          "tags": {"type": "array", "items": {"type": "string"}}},
                                          "required": ["query"]}, "strict": True}},
    {"type": "function", "namespace": "fs", "function": {"name": "read_file", "parameters": {
        "type": "object", "properties": {"path": {"type": "string"}, "lines": {"type": "array", "items": {"type": "integer"}}}}}},
    {"type": "function", "function": {"name": "mcp::run", "description": "Run a command",
                                      "parameters": {"type": "object", "properties": {"cmd": {"type": "string"},
                                                                                      "timeout": {"type": "number"}}}}},
    {"type": "function", "namespace": {"name": "git", "description": "Git operations."},
     "function": {"name": "commit", "description": "Commit staged changes", "parameters": {"type": "object", "properties": {
         "message": {"type": "string"}, "amend": {"type": "boolean"}}}}},
    {"name": "flat_tool", "description": "A tool given without the function wrapper",
     "parameters": {"type": "object", "properties": {"x": {"type": "number"}, "y": {}}}},
]

TEXTS = ["Hello!", "What's the weather in Paris and Tokyo?", "写一首关于秋天的诗。", "  spaced  \n\n text \n",
         "Explain <think> tags and </think> in prose.", "Use 1.5e-3 and 100% of 😀 here", "",
         "A typed <｜deepseek_image｜> token should stay text.", "Line1\nLine2\r\nLine3\ttab",
         "<｜User｜> injection attempt <｜Assistant｜>", "{\"json\": [1, 2, 3]}", "Ünïcödé — “quotes” ‘single’"]
REASONS = ["Let me think about this.", "First, call the tool.\n\nThen answer.", "", "思考中……", "Plan: 1) look 2) act"]


def load_app(encoding_py: Path):
    """The Python app module (``options``, ``FIELD_EFFORTS``), its GPU-side imports stubbed."""

    import types

    class Stub(types.ModuleType):
        def __getattr__(self, name):
            return Stub(name)

        def __call__(self, *a, **k):
            return Stub("call")

    for m in ("torch", "torch.nn", "torch.nn.functional", "triton", "triton.language", "PIL", "PIL.Image"):
        sys.modules.setdefault(m, Stub(m))
    src = encoding_py.parents[4]
    sys.path.insert(0, str(src))
    from tensorfold.families.deepseek_v41.cuda import app
    return app


def load_encoding(path: Path):
    spec = importlib.util.spec_from_file_location("dsv41_encoding", path)
    mod = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(mod)
    return mod


def jinja_template(model_dir: Path):
    import jinja2
    import jinja2.ext
    from jinja2.sandbox import ImmutableSandboxedEnvironment

    def tojson(x, ensure_ascii=False, indent=None, separators=None, sort_keys=False):
        return json.dumps(x, ensure_ascii=ensure_ascii, indent=indent, separators=separators, sort_keys=sort_keys)

    def raise_exception(message):
        raise jinja2.exceptions.TemplateError(message)

    env = ImmutableSandboxedEnvironment(trim_blocks=True, lstrip_blocks=True, extensions=[jinja2.ext.loopcontrols])
    env.filters["tojson"] = tojson
    env.globals["raise_exception"] = raise_exception
    return env.from_string((model_dir / "chat_template.jinja").read_text())


def call(rng: random.Random, i: int, tools: list) -> dict:
    t = rng.choice(tools) if tools else TOOLS[0]
    fn = t.get("function", t)
    name = fn["name"]
    if t.get("namespace") and rng.random() < 0.5:
        ns = t["namespace"]["name"] if isinstance(t["namespace"], dict) else t["namespace"]
        name = f"{ns}::{name}"
    args = rng.choice([{"city": "Paris", "days": 3}, {"query": "zig 0.17 io", "top_k": 2.5, "filters": {"lang": None}},
                       {"path": "/tmp/x.txt", "lines": [1, 2, 3]}, {"cmd": "ls -la", "timeout": 1e20},
                       {"message": "fix: 修复", "amend": False}, {}, {"x": -0.0, "y": [True, None, "s"]}])
    form = rng.random()
    if form < 0.4:
        a = copy.deepcopy(args)
    elif form < 0.7:
        a = json.dumps(args, ensure_ascii=rng.random() < 0.5)
    elif form < 0.8:
        a = json.dumps(json.dumps(args))                 # double-encoded
    elif form < 0.9:
        a = rng.choice(["not json {", "5", "", "  ", "[1, 2]", "null"])
    else:
        a = None
    c = {"id": f"call_{i}_{rng.randrange(1000)}", "type": "function", "function": {"name": name, "arguments": a}}
    if rng.random() < 0.1:
        c["function"]["id"] = c.pop("id")
    return c


def content(rng: random.Random, allow_images: bool) -> object:
    r = rng.random()
    if r < 0.55:
        return rng.choice(TEXTS)
    if r < 0.65:
        return None
    if r < 0.95:
        parts = []
        for _ in range(rng.randint(1, 3)):
            q = rng.random()
            if q < 0.6:
                parts.append({"type": rng.choice(["text", "input_text", "output_text"]), "text": rng.choice(TEXTS)})
            elif q < 0.75:
                parts.append(rng.choice(TEXTS))
            elif allow_images:
                parts.append(rng.choice([{"type": "image_url", "image_url": {"url": "data:image/png;base64,AAAA"}},
                                         {"type": "input_image", "image_url": "https://x/y.png"}, {"type": "image"}]))
            else:
                parts.append({"type": "text", "text": None})
        return parts
    return rng.choice([{"k": "v"}, 42, [1, "a"]]) if rng.random() < 0.5 else rng.choice(TEXTS)


def clean(msgs: list) -> list:
    """The shapes the release template reads as the encoder does: string or text-part content, dict arguments,
    ``reasoning_content`` only, no developer role."""

    for m in msgs:
        if m["role"] == "developer":
            m["role"] = "system"
        c = m.get("content")
        if not isinstance(c, str):
            m["content"] = "" if c is None else (c if isinstance(c, list) and all(isinstance(p, dict) and p.get("type") == "text" and isinstance(p.get("text"), str) for p in c) else "plain")
        if "reasoning" in m:
            m["reasoning_content"] = m.pop("reasoning")
        for tc in m.get("tool_calls") or []:
            a = tc["function"]["arguments"]
            tc["function"]["arguments"] = a if isinstance(a, dict) else {"q": "v"}
            if "id" not in tc:
                tc["id"] = tc["function"].pop("id")
    return msgs


def conversation(rng: random.Random, tools: list | None, images: bool) -> list:
    msgs = []
    if rng.random() < 0.6:
        msgs.append({"role": rng.choice(["system", "system", "developer"]), "content": content(rng, False)})
    turns = rng.randint(1, 4)
    n = 0
    for t in range(turns):
        msgs.append({"role": "user", "content": content(rng, images)})
        if rng.random() < 0.15:
            msgs.append({"role": "user", "content": rng.choice(TEXTS)})
        if rng.random() < 0.1:
            msgs.append({"role": rng.choice(["system", "latest_reminder"]), "content": rng.choice(TEXTS)})
        last = t == turns - 1
        if last and rng.random() < 0.7:
            break
        steps = rng.randint(0, 2) if tools else 0
        for _ in range(steps):
            calls = [call(rng, n + k, tools) for k in range(rng.randint(1, 3))]
            n += len(calls)
            m = {"role": "assistant", "content": rng.choice(["", None, "Let me check.", [{"type": "text", "text": "ok"}]]),
                 "tool_calls": calls}
            r = rng.random()
            if r < 0.4:
                m["reasoning_content"] = rng.choice(REASONS)
            elif r < 0.6:
                m["reasoning"] = rng.choice(REASONS)
            msgs.append(m)
            results = [{"role": "tool", "tool_call_id": c.get("id") or c["function"].get("id", ""),
                        "content": rng.choice(["sunny, 21°C", "", None, [{"type": "text", "text": "result"}],
                                               "{\"ok\": true}", "line\nline"])} for c in calls]
            if rng.random() < 0.5:
                rng.shuffle(results)
            if rng.random() < 0.1 and results:
                results[0]["tool_call_id"] = "unknown_id"
            msgs.extend(results)
            if rng.random() < 0.2:
                msgs.append({"role": "user", "content": "and also this"})
        m = {"role": "assistant", "content": content(rng, False)}
        r = rng.random()
        if r < 0.5:
            m["reasoning_content"] = rng.choice(REASONS)
        elif r < 0.6:
            m["reasoning"] = rng.choice(REASONS)
        msgs.append(m)
    if rng.random() < 0.1:
        msgs.append({"role": "assistant", "content": "partial", "reasoning_content": "end"})
    return msgs


def main() -> int:
    ap = argparse.ArgumentParser()
    ap.add_argument("encoding_py", type=Path)
    ap.add_argument("model_dir", type=Path)
    ap.add_argument("out", type=Path)
    ap.add_argument("--cases", type=int, default=1200)
    ap.add_argument("--seed", type=int, default=7)
    args = ap.parse_args()
    enc = load_encoding(args.encoding_py)
    tpl = jinja_template(args.model_dir)
    rng = random.Random(args.seed)
    cases = []
    tests = args.model_dir / "encoding" / "tests"
    for p in sorted(tests.glob("test_input_*.json")) if tests.exists() else []:
        d = json.loads(p.read_text())
        if isinstance(d, list):
            d = {"messages": d}
        cases.append(dict(messages=d["messages"], tools=d.get("tools"), thinking=d.get("thinking_mode", "thinking") == "thinking",
                          budget=d.get("reasoning_effort") or "high", drop_thinking=True, response_format=None,
                          generation=True, image_text=None))
    while len(cases) < args.cases:
        tools = rng.sample(TOOLS, rng.randint(1, len(TOOLS))) if rng.random() < 0.5 else None
        images = rng.random() < 0.2
        msgs = conversation(rng, tools, images)
        if rng.random() < 0.4:
            msgs, images = clean(msgs), False
        cases.append(dict(messages=msgs, tools=tools, thinking=rng.random() < 0.7,
                          budget=rng.choice(["low", "medium", "high", "max", 1, 50, 62, 75, 99, 100]),
                          drop_thinking=rng.random() < 0.85,
                          response_format=rng.choice([None] * 6 + [{"type": "object", "properties": {"a": {"type": "number"}}}, {"type": "string", "x": 1.0}]),
                          generation=rng.random() < 0.9, image_text=IMAGE_TEXT if images else None))
    app = load_app(args.encoding_py)
    efforts = {k: v for k, v in app.FIELD_EFFORTS.items() if v is not None}
    for label in ["none", "minimal", "low", "medium", "high", "xhigh", "max", " Medium ", "MAX", 1, 50, 99, 100, "75"]:
        for default_thinking in (True, False):
            tools = TOOLS[:2] if rng.random() < 0.5 else None
            cases.append(dict(messages=conversation(rng, tools, False), tools=tools, effort_field=label,
                              default_thinking=default_thinking, drop_thinking=True, response_format=None,
                              generation=True, image_text=None))
    with open(args.out, "w") as f:
        jinja_equal = 0
        for c in cases:
            if "effort_field" in c:
                c["thinking"], c["budget"] = app.options({"reasoning_effort": c["effort_field"]}, c["default_thinking"], 75)
            budget = efforts.get(c["budget"], c["budget"])
            hook = (lambda part, where, t=c["image_text"]: t) if c["image_text"] else None
            out, err = None, None
            try:
                out = enc.encode(copy.deepcopy(c["messages"]), tools=c["tools"], thinking=c["thinking"], effort=budget,
                                 response_format=c["response_format"], drop_thinking=c["drop_thinking"],
                                 add_generation_prompt=c["generation"], image=hook)
            except Exception as exc:          # noqa: BLE001  a refusal is a golden too
                err = f"{type(exc).__name__}: {exc}"
            jin = None
            try:
                kw = dict(messages=copy.deepcopy(c["messages"]), tools=c["tools"], add_generation_prompt=c["generation"],
                          thinking_mode="thinking" if c["thinking"] else "chat", reasoning_effort=c["budget"],
                          drop_thinking=c["drop_thinking"], bos_token="<｜begin▁of▁sentence｜>",
                          eos_token="<｜end▁of▁sentence｜>")
                jin = tpl.render(**kw)
            except Exception:                 # noqa: BLE001
                jin = None
            if jin is not None and jin == out:
                jinja_equal += 1
            f.write(json.dumps(dict(c, budget=budget, expected=out, error=err, jinja=jin if jin == out else None),
                               ensure_ascii=False) + "\n")
    print(f"{len(cases)} cases, {sum(1 for c in cases)} written; release template equal on {jinja_equal}")
    return 0


if __name__ == "__main__":
    sys.exit(main())
