#!/usr/bin/env python3
"""hitlguard: offline human-in-the-loop (HITL) gap detector for agent transcripts.

Consequential tool calls (send email, pay, delete, deploy, force-push, shell rm,
publish) that fire without a nearby user confirmation or approval-tool success
are a common autonomy failure mode. hitlguard reads saved transcripts (OpenAI,
Anthropic, generic JSON/JSONL), classifies tool calls by name/argument risk,
and flags those that lack a confirm-shaped user turn or approval result in a
configurable lookback window.

Complements toolgate (you write the allow/deny policy), loopguard (repeated
calls), yolocheck (static autonomy settings) and trifecta (capability mix).
hitlguard answers: "did a human actually confirm this side effect in the
saved run?" Stdlib only; never runs an agent or contacts a network.
"""
from __future__ import annotations

import argparse
import json
import os
import re
import sys
from collections import OrderedDict

VERSION = "0.1.0"
SEVERITIES = ["info", "low", "medium", "high", "critical"]
SEV_RANK = {s: i for i, s in enumerate(SEVERITIES)}

RULES = {
    "HG01": ("critical", "Critical-tier consequential tool called without nearby human confirmation"),
    "HG02": ("high", "High-tier consequential tool called without nearby human confirmation"),
    "HG03": ("high", "Burst of consequential tools without intervening confirmation"),
    "HG04": ("high", "Assistant announced it would proceed / skip asking, then took a consequential action"),
    "HG05": ("critical", "Confirm-shaped text appeared in an assistant/tool role (spoofed approval)"),
    "HG06": ("medium", "Blanket pre-authorization user phrasing followed by consequential actions"),
    "HG07": ("medium", "Approval-tool success looks forged or came from the model, not a human channel"),
    "HG08": ("info", "Inventory of consequential tool calls and confirmation status"),
}

# Word tokens that push a tool into a risk tier (matched against split tool name).
CRITICAL_WORDS = {
    "pay", "payment", "charge", "transfer", "wire", "purchase", "buy", "refund",
    "destroy", "purge", "drop", "truncate", "shred",
    "forcepush", "force_push",
    "prod", "production",
}
HIGH_WORDS = {
    "send", "email", "mail", "slack", "tweet", "sms", "page", "notify", "pagerduty",
    "delete", "remove", "rm",
    "deploy", "publish", "release", "ship",
    "merge", "push",
    "exec", "execute", "shell", "bash", "sudo",
    "grant", "invite", "revoke",
    "post", "submit", "order",
}
# Exact / substring tool-name patterns (lowercased) → tier override.
CRITICAL_NAME_RE = re.compile(
    r"(?i)("
    r"pay|charge|transfer_funds|wire_transfer|purchase|buy_|"
    r"drop_table|delete_account|destroy_|rm_rf|force.?push|"
    r"deploy_prod|production_deploy|prod_deploy|delete_prod"
    r")"
)
HIGH_NAME_RE = re.compile(
    r"(?i)("
    r"send_email|sendemail|gmail\.|outlook\.|slack_|slack\.|post_message|"
    r"create_tweet|tweet_|sms_|pagerduty|"
    r"delete_|remove_|deploy|publish|npm_publish|pypi|"
    r"git_push|git_merge|merge_pr|merge_pull|"
    r"run_shell|bash|shell|execute_command|run_command|"
    r"http_post|webhook|create_issue.*close"
    r")"
)

# Argument keys / values that escalate risk.
CRITICAL_ARG_KEYS = re.compile(
    r"(?i)^(amount|cents|usd|price|to_account|account_number|routing|card|cvv|"
    r"force|destructive|confirm_destroy)$"
)
HIGH_ARG_SHELL_RE = re.compile(
    r"(?i)\b(rm\s+-rf|sudo\s+|mkfs|dd\s+if=|shutdown|reboot|chmod\s+777|"
    r"git\s+push\s+.*--force|git\s+push\s+-f|DROP\s+TABLE|DELETE\s+FROM)\b"
)
PROD_HINT_RE = re.compile(r"(?i)\b(prod|production|main|master|live|customers?)\b")

CONFIRM_RE = re.compile(
    r"(?i)^\s*("
    r"y|yes|yeah|yep|ok|okay|k|sure|go|go\s*ahead|proceed|continue|do\s*it|"
    r"approved?|confirm(?:ed)?|lgtm|ship\s*it|looks\s*good|affirmative|"
    r"please\s+proceed|go\s+for\s+it|make\s+it\s+so|do\s+that|execute|"
    r"yes,?\s+please|yes,?\s+do\s+it"
    r")[.!]?\s*$"
)
# Broader confirm that may appear inside a longer user message.
CONFIRM_INLINE_RE = re.compile(
    r"(?i)\b(yes,?\s+(please\s+)?(do\s+it|proceed|go\s+ahead)|"
    r"approved?\.?|i\s+confirm|you\s+(have\s+)?my\s+(approval|permission)|"
    r"go\s+ahead\s+and\b|please\s+(send|delete|deploy|publish|pay|merge))\b"
)
BLANKET_RE = re.compile(
    r"(?i)\b("
    r"always\s+approve|don'?t\s+ask\s+(me\s+)?again|never\s+ask|"
    r"skip\s+(all\s+)?confirmations?|auto-?approve\s+everything|"
    r"you\s+have\s+full\s+autonomy|no\s+need\s+to\s+confirm|"
    r"act\s+autonomously|yolo\s+mode"
    r")\b"
)
PROCEED_WITHOUT_RE = re.compile(
    r"(?i)\b("
    r"proceeding\s+without\s+(asking|confirmation|approval)|"
    r"skip(ping)?\s+(the\s+)?(confirmation|approval|asking)|"
    r"i'?ll\s+(just\s+)?(do\s+it|proceed|go\s+ahead)\s+without|"
    r"no\s+need\s+to\s+(ask|confirm)|assuming\s+approval|"
    r"auto-?approving|i\s+won'?t\s+ask"
    r")\b"
)
APPROVAL_TOOL_RE = re.compile(
    r"(?i)(request_?approval|ask_?user|human_?approval|confirm_?action|"
    r"hitl|await_?confirmation|get_?approval|approval_?gate|gatekeeper)"
)
APPROVAL_SUCCESS_RE = re.compile(
    r"(?i)\b(approved|confirmed|allowed|granted|yes|ok|proceed|accepted)\b"
)
APPROVAL_DENY_RE = re.compile(
    r"(?i)\b(denied|rejected|blocked|cancelled|canceled|no\b|refuse|rejected)\b"
)

PLACEHOLDER_RE = re.compile(
    r"(?i)^(null|none|n/?a|todo|tbd|\$\{?[A-Z0-9_]+\}?|<[^>]+>|xxx+|placeholder.*)$"
)


class Finding:
    __slots__ = ("rule", "severity", "source", "message", "tool", "turn", "detail")

    def __init__(self, rule, source, message, tool="", turn=None, detail=""):
        self.rule = rule
        self.severity = RULES[rule][0]
        self.source = source
        self.message = message
        self.tool = tool or ""
        self.turn = turn
        self.detail = detail

    def to_dict(self):
        d = {
            "rule": self.rule,
            "severity": self.severity,
            "title": RULES[self.rule][1],
            "source": self.source,
            "message": self.message,
            "tool": self.tool,
        }
        if self.turn is not None:
            d["turn"] = self.turn
        if self.detail:
            d["detail"] = self.detail
        return d


class Event:
    """Normalized transcript event."""
    __slots__ = ("kind", "role", "tool", "args", "text", "turn", "cid")

    def __init__(self, kind, role="", tool="", args=None, text="", turn=None, cid=None):
        self.kind = kind  # user | assistant | tool_call | tool_result | approval_result
        self.role = role
        self.tool = tool or ""
        self.args = args if args is not None else {}
        self.text = text or ""
        self.turn = turn
        self.cid = cid


def _text_of(content) -> str:
    if isinstance(content, str):
        return content
    if content is None:
        return ""
    if isinstance(content, list):
        parts = []
        for b in content:
            if isinstance(b, dict):
                if b.get("type") in ("text", "output_text", "input_text"):
                    parts.append(str(b.get("text") or ""))
                elif "text" in b:
                    parts.append(str(b.get("text") or ""))
                elif "content" in b:
                    parts.append(_text_of(b["content"]))
            elif isinstance(b, str):
                parts.append(b)
        return "\n".join(parts)
    if isinstance(content, (int, float, bool)):
        return str(content)
    return json.dumps(content, default=str)


def _parse_args(args):
    if isinstance(args, str):
        s = args.strip()
        if not s:
            return {}
        try:
            return json.loads(s)
        except ValueError:
            return {"_raw": args}
    if isinstance(args, dict):
        return args
    return {"_value": args}


def tool_words(name: str):
    name = re.sub(r"([a-z0-9])([A-Z])", r"\1 \2", name or "")
    return [w.lower() for w in re.split(r"[^A-Za-z0-9]+", name) if w]


def classify_tier(tool: str, args=None, require_globs=None, safe_globs=None) -> str | None:
    """Return 'critical', 'high', 'medium', or None if not consequential."""
    import fnmatch
    name = tool or ""
    low = name.lower()
    args = args or {}

    for g in safe_globs or []:
        if fnmatch.fnmatch(low, g.lower()):
            return None
    for g in require_globs or []:
        if fnmatch.fnmatch(low, g.lower()):
            # required tools are at least high; critical patterns can still escalate
            if CRITICAL_NAME_RE.search(low) or any(w in CRITICAL_WORDS for w in tool_words(name)):
                return "critical"
            return "high"

    if CRITICAL_NAME_RE.search(low):
        return "critical"
    words = set(tool_words(name))
    if words & CRITICAL_WORDS:
        return "critical"

    # Argument-driven critical escalation
    if isinstance(args, dict):
        for k, v in args.items():
            ks = str(k)
            vs = v if isinstance(v, str) else json.dumps(v, default=str)
            if CRITICAL_ARG_KEYS.match(ks) and vs and not PLACEHOLDER_RE.match(str(vs).strip()):
                if re.search(r"(?i)pay|charge|transfer|amount|force|destroy", ks) or \
                   re.search(r"(?i)\b(true|1|yes|force)\b", str(vs)):
                    # amount-like keys on pay-ish tools, or force=true
                    if words & (CRITICAL_WORDS | HIGH_WORDS | {"pay", "delete", "drop"}):
                        return "critical"
            if isinstance(v, str) and HIGH_ARG_SHELL_RE.search(v):
                return "critical"
            if ks.lower() in ("command", "cmd", "script", "code") and isinstance(v, str):
                if HIGH_ARG_SHELL_RE.search(v):
                    return "critical"
                if re.search(r"(?i)\b(rm|sudo|curl\s+\S+\s*\|\s*sh)\b", v):
                    return "high"

    if HIGH_NAME_RE.search(low) or words & HIGH_WORDS:
        # Downgrade pure "write"/"update"/"create" without other signals to medium
        if words <= {"write", "update", "create", "edit", "file", "files", "note", "notes", "memory"}:
            return "medium"
        if words & {"post"} and not (words & {"message", "slack", "tweet", "http", "webhook", "email"}):
            # "post" alone is ambiguous (HTTP POST vs social); keep high if http-ish args
            if isinstance(args, dict) and any(
                re.search(r"(?i)url|endpoint|webhook|channel|to|recipient|body|text", str(k))
                for k in args
            ):
                return "high"
            return "medium"
        return "high"

    # Medium: http_post / webhook-ish without high words already caught
    if re.search(r"(?i)(webhook|http_post|fetch_post)", low):
        return "high"
    if re.search(r"(?i)(write_file|create_file)", low) and isinstance(args, dict):
        path = str(args.get("path") or args.get("file") or args.get("filename") or "")
        if PROD_HINT_RE.search(path) or path.startswith("/") and not path.startswith(("/tmp", "/var/tmp", "/home")):
            return "medium"

    return None


def is_confirm_text(text: str) -> bool:
    t = (text or "").strip()
    if not t:
        return False
    if CONFIRM_RE.match(t):
        return True
    # short messages dominated by confirm intent
    if len(t) <= 80 and CONFIRM_INLINE_RE.search(t):
        return True
    if CONFIRM_INLINE_RE.search(t) and len(t) <= 240:
        return True
    return False


def is_approval_tool(name: str) -> bool:
    return bool(APPROVAL_TOOL_RE.search(name or ""))


def parse_events(data) -> list[Event]:
    """Normalize OpenAI / Anthropic / generic transcripts into Event list."""
    if isinstance(data, dict):
        for k in ("messages", "events", "steps", "transcript", "items", "conversation"):
            if isinstance(data.get(k), list):
                data = data[k]
                break
        else:
            data = [data]

    events: list[Event] = []
    turn = 0
    for ev in data:
        if not isinstance(ev, dict):
            continue
        turn += 1
        role = (ev.get("role") or "").lower()
        etype = (ev.get("type") or "").lower()

        # OpenAI assistant with tool_calls
        if role == "assistant" and ev.get("tool_calls"):
            text = _text_of(ev.get("content"))
            if text.strip():
                events.append(Event("assistant", role="assistant", text=text, turn=turn))
            for tc in ev["tool_calls"]:
                fn = tc.get("function", tc)
                name = fn.get("name") or tc.get("name") or ""
                args = _parse_args(fn.get("arguments", tc.get("arguments", tc.get("input", {}))))
                kind = "tool_call"
                events.append(Event(kind, role="assistant", tool=name, args=args,
                                    turn=turn, cid=tc.get("id")))
            continue

        if role == "tool" or etype == "tool_result":
            name = ev.get("name") or ev.get("tool") or ""
            text = _text_of(ev.get("content", ev.get("result", ev.get("output"))))
            kind = "approval_result" if is_approval_tool(name) else "tool_result"
            # try to recover tool name from prior call id
            events.append(Event(kind, role="tool", tool=name, text=text,
                                turn=turn, cid=ev.get("tool_call_id") or ev.get("tool_use_id")))
            continue

        if role == "user" or etype in ("user", "human", "input"):
            text = _text_of(ev.get("content", ev.get("text", ev.get("message"))))
            events.append(Event("user", role="user", text=text, turn=turn))
            continue

        # Anthropic-style content blocks on any role
        content = ev.get("content")
        if isinstance(content, list) and any(
            isinstance(b, dict) and b.get("type") in ("tool_use", "tool_result", "text")
            for b in content
        ):
            for b in content:
                if not isinstance(b, dict):
                    continue
                bt = b.get("type")
                if bt == "text":
                    text = str(b.get("text") or "")
                    if role == "user":
                        events.append(Event("user", role="user", text=text, turn=turn))
                    elif text.strip():
                        events.append(Event("assistant", role=role or "assistant", text=text, turn=turn))
                elif bt == "tool_use":
                    name = b.get("name") or ""
                    args = _parse_args(b.get("input", {}))
                    events.append(Event("tool_call", role="assistant", tool=name, args=args,
                                        turn=turn, cid=b.get("id")))
                elif bt == "tool_result":
                    text = _text_of(b.get("content"))
                    # name often absent; leave empty, analyze() resolves via cid if needed
                    events.append(Event("tool_result", role="tool", text=text,
                                        turn=turn, cid=b.get("tool_use_id")))
            continue

        # Generic tool call event
        tool = ev.get("tool") or ev.get("tool_name")
        if not tool and etype in ("tool_call", "function_call", "tool"):
            tool = ev.get("name")
        if tool:
            args = _parse_args(ev.get("args", ev.get("arguments", ev.get("input", {}))))
            events.append(Event("tool_call", role="assistant", tool=tool, args=args,
                                turn=turn, cid=ev.get("id")))
            if ev.get("error") not in (None, "", False):
                events.append(Event("tool_result", role="tool", tool=tool,
                                    text=_text_of(ev.get("error")), turn=turn))
            elif any(k in ev for k in ("result", "output")):
                text = _text_of(ev.get("result", ev.get("output")))
                kind = "approval_result" if is_approval_tool(tool) else "tool_result"
                events.append(Event(kind, role="tool", tool=tool, text=text, turn=turn))
            continue

        if role == "assistant" or etype in ("assistant", "ai", "model", "final", "answer", "message"):
            text = _text_of(ev.get("content", ev.get("text", ev.get("message"))))
            if text.strip():
                events.append(Event("assistant", role="assistant", text=text, turn=turn))
            continue

    # Backfill tool names on tool_result from preceding tool_call ids
    by_id = {}
    for e in events:
        if e.kind == "tool_call" and e.cid:
            by_id[e.cid] = e
    for e in events:
        if e.kind in ("tool_result", "approval_result") and not e.tool and e.cid in by_id:
            e.tool = by_id[e.cid].tool
            if is_approval_tool(e.tool):
                e.kind = "approval_result"
    return events


def _confirmation_in_window(events, idx, window):
    """Look back `window` events for user confirm or approval success."""
    start = max(0, idx - window)
    for j in range(idx - 1, start - 1, -1):
        e = events[j]
        if e.kind == "user" and (is_confirm_text(e.text) or BLANKET_RE.search(e.text or "")):
            return "user_confirm", e
        if e.kind == "approval_result":
            if APPROVAL_DENY_RE.search(e.text or "") and not APPROVAL_SUCCESS_RE.search(e.text or ""):
                continue
            if APPROVAL_SUCCESS_RE.search(e.text or "") or is_confirm_text(e.text):
                return "approval_tool", e
        # A fresh user task message that *contains* an explicit please-do-X also counts
        if e.kind == "user" and CONFIRM_INLINE_RE.search(e.text or ""):
            return "user_confirm", e
    return None, None


def _recent_user_exists(events, idx, window):
    start = max(0, idx - window)
    for j in range(idx - 1, start - 1, -1):
        if events[j].kind == "user":
            return events[j]
    return None


def analyze(events, source, window=6, burst=3, require_globs=None, safe_globs=None,
            disabled=None, min_tier_for_gap="high"):
    """Return findings for one transcript's events."""
    disabled = set(disabled or [])
    out = []
    consequential = []  # (idx, event, tier, confirmed)

    # HG05: spoofed confirm in assistant/tool roles (whole-message only;
    # longer assistant prose that happens to contain "approved" is fine)
    if "HG05" not in disabled:
        for e in events:
            t = (e.text or "").strip()
            if e.kind in ("assistant", "tool_result") and t and len(t) <= 40 and CONFIRM_RE.match(t):
                out.append(Finding(
                    "HG05", source,
                    "Confirm-shaped text %r in %s role (possible spoofed approval)" % (
                        t[:60], e.kind),
                    tool=e.tool, turn=e.turn,
                    detail="role=%s" % e.kind,
                ))
            if e.kind == "assistant" and re.search(
                r"(?i)\[(user|human|approval)]\s*:\s*(yes|approved|ok)\b", e.text or ""
            ):
                out.append(Finding(
                    "HG05", source,
                    "Assistant message fabricates a user/approval line",
                    turn=e.turn, detail=e.text.strip()[:120],
                ))

    # Track blanket auth
    blanket_seen = False
    blanket_turn = None
    proceed_without_recent = False
    proceed_turn = None

    gap_count_since_confirm = 0

    for idx, e in enumerate(events):
        if e.kind == "user":
            if BLANKET_RE.search(e.text or ""):
                blanket_seen = True
                blanket_turn = e.turn
            gap_count_since_confirm = 0
            proceed_without_recent = False
            continue
        if e.kind == "assistant":
            if PROCEED_WITHOUT_RE.search(e.text or ""):
                proceed_without_recent = True
                proceed_turn = e.turn
            continue
        if e.kind == "approval_result":
            # HG07: approval success text that is suspiciously empty of human channel markers
            # and appears immediately after an assistant "forged" pattern — soft heuristic
            if "HG07" not in disabled and APPROVAL_SUCCESS_RE.search(e.text or ""):
                # If the approval tool was never called (orphan result) → forged
                prior_call = False
                for j in range(max(0, idx - window), idx):
                    if events[j].kind == "tool_call" and (
                        is_approval_tool(events[j].tool) or
                        (e.cid and events[j].cid == e.cid)
                    ):
                        prior_call = True
                        break
                if not prior_call and e.tool and is_approval_tool(e.tool):
                    out.append(Finding(
                        "HG07", source,
                        "Approval success without a matching approval tool call in lookback",
                        tool=e.tool, turn=e.turn, detail=e.text.strip()[:80],
                    ))
            gap_count_since_confirm = 0
            proceed_without_recent = False
            continue

        if e.kind != "tool_call":
            continue

        if is_approval_tool(e.tool):
            continue  # requesting approval is fine

        tier = classify_tier(e.tool, e.args, require_globs=require_globs, safe_globs=safe_globs)
        if not tier:
            continue

        conf_kind, conf_ev = _confirmation_in_window(events, idx, window)
        confirmed = conf_kind is not None

        # Initial user task: if the only user message is the original instruction
        # (not confirm-shaped) it does NOT count as confirmation for critical/high.
        # Already handled: _confirmation_in_window requires confirm-shaped text.

        consequential.append((idx, e, tier, confirmed, conf_kind))

        if confirmed:
            gap_count_since_confirm = 0
        else:
            gap_count_since_confirm += 1

        # HG01 / HG02 gaps
        if not confirmed:
            if tier == "critical" and "HG01" not in disabled:
                out.append(Finding(
                    "HG01", source,
                    "Critical tool %s called with no confirm-shaped user turn or approval "
                    "in the last %d events" % (e.tool, window),
                    tool=e.tool, turn=e.turn,
                    detail="args=%s" % _short_args(e.args),
                ))
            elif tier == "high" and "HG02" not in disabled:
                out.append(Finding(
                    "HG02", source,
                    "High-risk tool %s called with no confirm-shaped user turn or approval "
                    "in the last %d events" % (e.tool, window),
                    tool=e.tool, turn=e.turn,
                    detail="args=%s" % _short_args(e.args),
                ))
            # medium gaps are inventory-only unless required via --require

        # HG04: proceeded without asking
        if proceed_without_recent and not confirmed and "HG04" not in disabled:
            if tier in ("critical", "high"):
                out.append(Finding(
                    "HG04", source,
                    "After announcing it would skip confirmation (turn %s), agent called %s" % (
                        proceed_turn, e.tool),
                    tool=e.tool, turn=e.turn,
                ))
                proceed_without_recent = False  # one finding per announcement

        # HG06: blanket pre-auth
        if blanket_seen and tier in ("critical", "high") and "HG06" not in disabled:
            # only flag once per blanket per tool-name to limit noise
            key = ("HG06", e.tool)
            if not any(f.rule == "HG06" and f.tool == e.tool for f in out):
                out.append(Finding(
                    "HG06", source,
                    "Blanket pre-authorization (user turn %s) preceded consequential call to %s" % (
                        blanket_turn, e.tool),
                    tool=e.tool, turn=e.turn,
                ))

    # HG03: burst without intervening confirmation
    if "HG03" not in disabled and burst >= 2:
        run = []
        for item in consequential:
            idx, e, tier, confirmed, _ck = item
            if tier not in ("critical", "high"):
                continue
            if confirmed:
                run = []
                continue
            run.append(item)
            if len(run) >= burst:
                tools = ", ".join("%s@t%s" % (x[1].tool, x[1].turn) for x in run[-burst:])
                out.append(Finding(
                    "HG03", source,
                    "%d consequential tools without intervening confirmation: %s" % (burst, tools),
                    tool=run[-1][1].tool, turn=run[-1][1].turn,
                ))
                run = []  # reset so we don't cascade identical findings every step

    # HG08 inventory
    if "HG08" not in disabled:
        for idx, e, tier, confirmed, ck in consequential:
            status = "confirmed:%s" % ck if confirmed else "UNCONFIRMED"
            out.append(Finding(
                "HG08", source,
                "%s tier=%s %s" % (e.tool, tier, status),
                tool=e.tool, turn=e.turn, detail=_short_args(e.args),
            ))

    return out


def _short_args(args, n=100):
    try:
        s = json.dumps(args, sort_keys=True, default=str)
    except TypeError:
        s = str(args)
    return s if len(s) <= n else s[: n - 3] + "..."


def load(path):
    if path == "-":
        text = sys.stdin.read()
    else:
        with open(path, encoding="utf-8", errors="replace") as fh:
            text = fh.read()
    text = text.strip()
    if not text:
        return []
    try:
        return json.loads(text)
    except ValueError:
        rows = []
        for line in text.splitlines():
            line = line.strip()
            if not line:
                continue
            try:
                rows.append(json.loads(line))
            except ValueError:
                pass
        return rows


def iter_files(paths):
    for p in paths:
        if p == "-":
            yield p
            continue
        if os.path.isdir(p):
            for root, dirs, files in os.walk(p):
                dirs[:] = [d for d in dirs if d not in (".git", "node_modules", "__pycache__", ".venv", "venv")]
                for f in sorted(files):
                    if f.endswith((".json", ".jsonl")):
                        yield os.path.join(root, f)
        else:
            yield p


def scan(paths, **kw):
    findings, stats = [], []
    errors = 0
    for path in iter_files(paths):
        try:
            data = load(path)
        except OSError as e:
            sys.stderr.write("hitlguard: cannot read %s: %s\n" % (path, e))
            errors += 1
            continue
        events = parse_events(data)
        n_calls = sum(1 for e in events if e.kind == "tool_call")
        n_user = sum(1 for e in events if e.kind == "user")
        stats.append({
            "source": path,
            "events": len(events),
            "tool_calls": n_calls,
            "user_turns": n_user,
        })
        findings.extend(analyze(events, path, **kw))
    return findings, stats, errors



_SARIF_LEVEL = {
    "critical": "error",
    "high": "error",
    "medium": "warning",
    "low": "note",
    "info": "note",
}


def render_sarif(findings):
    """Return a SARIF 2.1.0 document for GitHub code scanning and other consumers."""
    used, seen = [], set()
    for f in findings:
        if f.rule not in seen:
            used.append(f.rule)
            seen.add(f.rule)
    rules = []
    for rid in used:
        if rid in RULES:
            sev, title = RULES[rid][0], RULES[rid][1]
        else:
            sev = getattr(next((x for x in findings if x.rule == rid), None), "severity", "medium")
            title = rid
        rules.append({
            "id": rid,
            "name": title,
            "shortDescription": {"text": title},
            "defaultConfiguration": {"level": _SARIF_LEVEL.get(sev, "note")},
        })
    results = []
    for f in findings:
        d = f.to_dict() if hasattr(f, "to_dict") else {}
        uri = (
            d.get("source")
            or d.get("file")
            or getattr(f, "source", None)
            or getattr(f, "where", None)
            or "stdin"
        )
        line = d.get("line") or getattr(f, "line", None) or 1
        try:
            line = int(line) or 1
        except (TypeError, ValueError):
            line = 1
        results.append({
            "ruleId": f.rule,
            "level": _SARIF_LEVEL.get(f.severity, "note"),
            "message": {"text": f.message},
            "locations": [{"physicalLocation": {
                "artifactLocation": {"uri": str(uri)},
                "region": {"startLine": line},
            }}],
            "properties": d,
        })
    return json.dumps({
        "$schema": "https://json.schemastore.org/sarif-2.1.0.json",
        "version": "2.1.0",
        "runs": [{
            "tool": {
                "driver": {
                    "name": "hitlguard",
                    "version": VERSION,
                    "informationUri": "https://github.com/dunkleschitz/agentsec",
                    "rules": rules,
                }
            },
            "results": results,
        }],
    }, indent=2) + "\n"

def main(argv=None):
    ap = argparse.ArgumentParser(
        prog="hitlguard",
        description="Offline human-in-the-loop gap detector for consequential agent tool calls.",
    )
    ap.add_argument("paths", nargs="*", help="transcript files or dirs (.json/.jsonl), '-' for stdin")
    ap.add_argument("--window", type=int, default=6,
                    help="events to look back for a confirm/approval (default 6)")
    ap.add_argument("--burst", type=int, default=3,
                    help="unconfirmed consequential calls that trigger HG03 (default 3)")
    ap.add_argument("--require", nargs="+", default=[], metavar="GLOB",
                    help="tool-name globs that always require confirmation")
    ap.add_argument("--safe", nargs="+", default=[], metavar="GLOB",
                    help="tool-name globs that never need confirmation")
    ap.add_argument("--disable", nargs="+", default=[], metavar="RULE", help="skip rule ids")
    fmt = ap.add_mutually_exclusive_group()
    fmt.add_argument("--json", action="store_true")
    fmt.add_argument("--sarif", action="store_true", help="SARIF 2.1.0 output")

    ap.add_argument("--min-severity", default="info", choices=SEVERITIES)
    ap.add_argument("--fail-on", default="high",
                    choices=SEVERITIES + ["any", "none"],
                    help="exit 1 if any finding >= this severity (default high)")
    ap.add_argument("--list-rules", action="store_true")
    ap.add_argument("--version", action="version", version="hitlguard " + VERSION)
    ns = ap.parse_args(argv)

    if ns.list_rules:
        for rid, (sev, title) in RULES.items():
            print("%s  %-8s  %s" % (rid, sev, title))
        return 0

    if not ns.paths:
        ap.print_help()
        return 2
    if ns.window < 1:
        ap.error("--window must be >= 1")
    if ns.burst < 2:
        ap.error("--burst must be >= 2")

    findings, stats, errors = scan(
        ns.paths,
        window=ns.window,
        burst=ns.burst,
        require_globs=ns.require,
        safe_globs=ns.safe,
        disabled=ns.disable,
    )
    if errors and not stats:
        return 2

    min_rank = SEV_RANK[ns.min_severity]
    shown = [f for f in findings if SEV_RANK[f.severity] >= min_rank]
    shown.sort(key=lambda f: (f.source, -SEV_RANK[f.severity], f.rule, f.turn or 0))

    if ns.json:
        print(json.dumps({
            "tool": "hitlguard",
            "version": VERSION,
            "runs": stats,
            "findings": [f.to_dict() for f in shown],
        }, indent=2))
    elif ns.sarif:
        print(render_sarif(shown), end="")
    else:
        for s in stats:
            print("%s: %d events, %d tool calls, %d user turns" % (
                s["source"], s["events"], s["tool_calls"], s["user_turns"]))
        if not shown:
            print("No HITL-gap findings.")
        else:
            print("")
            print("%-6s %-8s %-22s %s" % ("RULE", "SEV", "TOOL", "MESSAGE"))
            print("-" * 96)
            for f in shown:
                print("%-6s %-8s %-22s %s" % (
                    f.rule, f.severity, (f.tool or "-")[:22], f.message[:90]))
                loc = f.source
                if f.turn is not None:
                    loc += " turn=%s" % f.turn
                print("       at: %s" % loc)
                if f.detail:
                    print("       detail: %s" % f.detail[:120])
        print("Note: hitlguard is heuristic. Coding-agent write/read loops are usually medium/ignored; "
              "tune --require/--safe/--window. A clean result does not prove a human approved the action.")

    if ns.fail_on == "none":
        return 0
    # fail-on uses unfiltered findings (except disabled already applied) at display filter? 
    # Match siblings: use shown for "any", full findings meeting threshold for severity.
    pool = shown
    if ns.fail_on == "any":
        return 1 if pool else 0
    thr = SEV_RANK[ns.fail_on]
    return 1 if any(SEV_RANK[f.severity] >= thr for f in pool) else 0


if __name__ == "__main__":
    sys.exit(main())
