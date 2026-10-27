"""tps — command line interface.

Exit codes are part of the contract (scripts and agents depend on them):

    0    success
    1    usage or configuration error (including bad flags)
    2    missing credentials
    3    upstream/provider failure
    4    run completed but every request failed
    130  interrupted (partial results are kept)
"""

from __future__ import annotations

import argparse
import asyncio
import contextlib
import io
import json
import math
import os
import sys
from datetime import UTC, datetime
from pathlib import Path
from typing import Any

from . import __version__, core
from .ui import UI, Bar, Col, Progress

SCHEMA_VERSION = 1
CONFIG_CANDIDATES = ("targets.toml", "targets.gateway.toml")
CLAUDE_API_URL = "https://api.anthropic.com/v1"

STARTER_CONFIG = """\
# tps config — one [[targets]] block per upstream you want to measure.
# Generate it instead of typing it:
#   tps init --endpoint https://api.example.com/v1 --model ID --api-key-env VAR
#   tps discover <author>/<slug> --out targets.toml      (every OpenRouter endpoint)

[run]
reps = 7
concurrency = [1, 4]
warmup = 2
# temperature = 0.0    # the default; never sent to api = "anthropic" targets
prompts = ["prose-256"]
# baseline = "my-direct-endpoint"   # adds Δ columns to the report

[[targets]]
name = "my-direct-endpoint"
base_url = "https://api.example.com/v1"
model = "some-model-id"
api_key_env = "EXAMPLE_API_KEY"
price = { in_per_1m = 0.30, out_per_1m = 1.20 }

[[targets]]
name = "same-model-via-gateway"
base_url = "https://openrouter.ai/api/v1"
model = "vendor/model-name"
api_key_env = "OPENROUTER_API_KEY"
extra_body.provider = { only = ["example-provider"], allow_fallbacks = false }
"""


class Interrupted(core.TpsError):
    """Ctrl-C during a run; whatever finished is already on disk."""

    exit_code = 130


class Parser(argparse.ArgumentParser):
    """argparse exits 2 on bad usage, which would read as "missing credentials".
    Raise a UsageError instead so bad flags exit 1 and honour --json."""

    def error(self, message: str) -> None:  # type: ignore[override]
        raise core.UsageError(f"{message} — see `{self.prog} --help`")


# --------------------------------------------------------------------------
# helpers
# --------------------------------------------------------------------------


def stamp() -> str:
    return datetime.now(UTC).strftime("%Y-%m-%dT%H-%M-%SZ")


def resolve_config(path: Path | None) -> Path:
    if path:
        if not path.exists():
            raise core.UsageError(f"config not found: {path}")
        return path
    for candidate in CONFIG_CANDIDATES:
        if Path(candidate).exists():
            return Path(candidate)
    raise core.UsageError("no config found — run `tps init` to scaffold one, or pass -c <file>")


def require_keys(cfg: core.RunConfig) -> None:
    missing = [t for t in cfg.targets if t.needs_key()]
    if missing:
        envs = sorted({t.api_key_env for t in missing if t.api_key_env})
        raise core.MissingKeyError(
            f"missing credentials for: {', '.join(t.name for t in missing)}"
            + (
                f" — set {', '.join(envs)}"
                if envs
                else " — name the env var that holds the key (api_key_env, or --api-key-env)"
            )
            + " (or run with --mock)"
        )


def _price_pair(text: str | None) -> tuple[float, float] | None:
    if text is None:
        return None
    try:
        price_in, price_out = (float(p) for p in text.split(","))
    except ValueError:
        raise core.UsageError(
            f"--price takes IN,OUT in USD per 1M tokens, e.g. 0.14,0.42 — got {text!r}"
        ) from None
    if not all(math.isfinite(p) and p >= 0 for p in (price_in, price_out)):
        raise core.UsageError(f"--price takes two finite, non-negative numbers — got {text!r}")
    return price_in, price_out


def endpoint_config(
    url: str | None,
    args: argparse.Namespace,
    flag: str,
    run_block: str = core.DEFAULT_RUN_TOML,
) -> str | None:
    """A one-target config from flags, for endpoints no gateway lists.

    Returns None when `flag` wasn't given, after rejecting the flags that
    only make sense with it.
    """
    extras = {"--api-key-env": args.api_key_env, "--name": args.name, "--price": args.price}
    if flag == "--base-url":
        extras["--model"] = args.model
    if url is None and args.api == "anthropic":
        url = CLAUDE_API_URL  # `--api anthropic` alone means Anthropic's own endpoint
    elif url is None and args.api is not None:
        extras["--api"] = args.api
    if url is None:
        stray = [name for name, value in extras.items() if value is not None]
        if stray:
            verb = "needs" if len(stray) == 1 else "need"
            raise core.UsageError(f"{', '.join(stray)} {verb} {flag} (or set it in a config)")
        return None
    if not args.model:
        raise core.UsageError(f"{flag} needs --model — the model id that endpoint serves")
    return core.endpoint_toml(
        url,
        args.model,
        args.name,
        args.api_key_env,
        _price_pair(args.price),
        source=f"tps {args.command} {flag}",
        api=args.api or "openai",
        run_block=run_block,
    )


def check_mock(cfg: core.RunConfig, path: Path, mock: bool, ui: UI) -> None:
    """`mock = {…}` profiles only ever apply under --mock."""
    if mock:
        return
    profiled = [t.name for t in cfg.targets if t.mock is not None]
    if profiled and len(profiled) == len(cfg.targets):
        raise core.UsageError(
            f"{path} only defines mock targets — add --mock for synthetic data, "
            "or point -c at a real config"
        )
    if profiled:
        ui.warn(f"ignoring mock profiles on {', '.join(profiled)} (they only apply with --mock)")


def _int_list(text: str, flag: str) -> list[int]:
    try:
        return [int(c) for c in text.split(",") if c.strip()]
    except ValueError:
        raise core.UsageError(f"{flag} takes comma-separated integers, got {text!r}") from None


def apply_overrides(cfg: core.RunConfig, args: argparse.Namespace) -> None:
    if getattr(args, "reps", None) is not None:
        cfg.reps = args.reps
    if getattr(args, "concurrency", None) is not None:
        cfg.concurrency = _int_list(args.concurrency, "--concurrency")
    if getattr(args, "prompts", None) is not None:
        wanted = [p.strip() for p in args.prompts.split(",") if p.strip()]
        unknown = [p for p in wanted if p not in cfg.available_prompts]
        if unknown:
            raise core.UsageError(
                f"unknown prompt(s) {unknown}; have {sorted(cfg.available_prompts)}"
            )
        cfg.prompts = {p: cfg.available_prompts[p] for p in wanted}
    if getattr(args, "max_tokens", None) is not None:
        cfg.prompts = {
            name: {**spec, "max_tokens": args.max_tokens} for name, spec in cfg.prompts.items()
        }
    if getattr(args, "temperature", None) is not None:
        cfg.temperature = args.temperature
    if getattr(args, "timeout", None) is not None:
        cfg.timeout_s = args.timeout
    if getattr(args, "no_warmup", False):
        cfg.warmup = 0
    core.validate(cfg, "flags")


def _r(value: float | None, digits: int = 4) -> float | None:
    return None if value is None else round(value, digits)


def summarise(samples: list[dict[str, Any]], meta: dict[str, Any]) -> dict[str, Any]:
    """Structured result used by --json and the terminal tables alike.

    Latency/rate fields describe the lowest concurrency (`concurrency`); `ok`,
    `n` and `errors` count every request at every level — the reliability
    signal; `by_concurrency` breaks both down per level.
    """
    stats = core.summarize(samples)
    buckets, per_stream, totals = stats["buckets"], stats["per_stream"], stats["totals"]
    prices = {t["name"]: t for t in meta.get("targets", [])}
    order = {name: i for i, name in enumerate(prices)}
    rows: list[dict[str, Any]] = []
    for prompt, target in sorted(per_stream, key=lambda k: (k[0], order.get(k[1], 1e9), k[1])):
        info = prices.get(target, {})
        st = core.bucket_stats(per_stream[(prompt, target)])
        total = totals[(prompt, target)]
        by_conc = {}
        for (p, t, conc), bucket in sorted(buckets.items()):
            if p != prompt or t != target:
                continue
            level = core.bucket_stats(bucket)
            by_conc[str(conc)] = {
                "ttft_p50_s": _r(level["ttft_p50_s"]),
                "out_tps_p50": _r(level["out_tps_p50"], 2),
                "aggregate_tps": _r(level["aggregate_tps"], 2),
                "ok": level["ok"],
                "n": level["n"],
                "truncated": level["truncated"],
                "reasoning_only": level["reasoning_only"],
                "errors": level["errors"],
            }
        rows.append(
            {
                "prompt": prompt,
                "target": target,
                "model": info.get("model"),
                "base_url": info.get("base_url"),
                "pin": info.get("pin"),
                "concurrency": stats["min_conc"][prompt],
                "ttft_p50_s": _r(st["ttft_p50_s"]),
                "ttft_p90_s": _r(st["ttft_p90_s"]),
                "first_content_p50_s": _r(st["first_content_p50_s"]),
                "out_tps_p50": _r(st["out_tps_p50"], 2),
                "out_tps_p90": _r(st["out_tps_p90"], 2),
                "itl_p50_ms": _r(st["itl_p50_ms"], 2),
                "itl_n": st["itl_n"],
                "first_content_n": st["first_content_n"],
                "tokens_per_chunk_median": _r(st["tokens_per_chunk_median"], 2),
                "bursty": st["bursty"],
                "e2e_p50_s": _r(st["e2e_p50_s"]),
                "out_tokens_median": st["out_tokens_median"],
                # every concurrency level, like ok/n (per level: by_concurrency)
                "truncated": total["truncated"],
                "reasoning_only": total["reasoning_only"],
                "hidden_reasoning_tokens_median": st["hidden_reasoning_tokens_median"],
                "notes": core.row_notes(st),
                "ok": total["ok"],
                "n": total["n"],
                "errors": total["errors"],
                "aggregate_tps": {
                    c: v["aggregate_tps"] for c, v in by_conc.items() if v["aggregate_tps"]
                },
                "by_concurrency": by_conc,
                "count_source": st["count_source"],
                "served_by": st["served_by"],
                "price_in_per_1m": info.get("price_in"),
                "price_out_per_1m": info.get("price_out"),
            }
        )
    return {"rows": rows, "baseline": meta.get("baseline")}


# --------------------------------------------------------------------------
# terminal rendering
# --------------------------------------------------------------------------


def _secs(value: float | None) -> str:
    return "—" if value is None else f"{value:.2f}s"


def _ms(value: float | None) -> str:
    return "—" if value is None else f"{value:.0f}ms"


def _thinking(row: dict[str, Any]) -> bool:
    """Some responses at the row's own (lowest) level were reasoning only."""
    return bool(row["by_concurrency"][str(row["concurrency"])].get("reasoning_only"))


def _best(rows: list[dict[str, Any]], key, lowest: bool) -> float | None:
    values = [key(r) for r in rows if key(r) is not None]
    if len(values) < 2:
        return None
    return min(values) if lowest else max(values)


def print_run_table(ui: UI, summary: dict[str, Any], prompt: str) -> None:
    rows = [r for r in summary["rows"] if r["prompt"] == prompt and r["n"]]
    if not rows or ui.silent:
        return
    conc = rows[0]["concurrency"]
    level = str(conc)
    baseline = summary["baseline"]
    base = next((r for r in rows if r["target"] == baseline), None)
    show_delta = bool(base and base["ttft_p50_s"] is not None and base["out_tps_p50"])
    peak = max((r["out_tps_p50"] or 0 for r in rows), default=0)

    # a rate that timed thinking, not an answer, can't be "fastest"
    best_tps = _best(rows, lambda r: None if _thinking(r) else r["out_tps_p50"], lowest=False)
    best_ttft = _best(rows, lambda r: r["ttft_p50_s"], lowest=True)
    # a bursty ITL measures the proxy's flushing; it can't win "lowest ITL"
    best_itl = _best(rows, lambda r: None if r["bursty"] else r["itl_p50_ms"], lowest=True)
    cheapest = _best(rows, lambda r: r["price_out_per_1m"], lowest=True)

    def mark(value, best):
        return ui.best if best is not None and value == best else None

    cols = [
        Col("provider", "l"),
        Col("ttft"),
        Col("tok/s"),
        Col("", "l", flex=True),
        Col("itl", drop=1),
        Col("tok/chunk", drop=5),
        Col("ok"),
        Col("$/1M out", drop=2),
    ]
    if show_delta:
        cols += [Col("Δ ttft", drop=3), Col("Δ tok/s", drop=4)]

    estimated = False
    table = []
    for r in rows:
        est = core.is_estimated(r["count_source"])
        estimated |= est
        ok, n = r["by_concurrency"][level]["ok"], r["by_concurrency"][level]["n"]
        ok_style = ui.green if ok == n else ui.red if ok == 0 else ui.yellow
        is_best = best_tps is not None and r["out_tps_p50"] == best_tps
        cells: list[Any] = [
            (r["target"], ui.bold if is_best else None),
            (_secs(r["ttft_p50_s"]), mark(r["ttft_p50_s"], best_ttft)),
            (("≈" if est else "") + core.fmt(r["out_tps_p50"]), mark(r["out_tps_p50"], best_tps)),
            Bar(r["out_tps_p50"], peak, 24, ui.green if is_best else ui.cyan),
            (
                (_ms(r["itl_p50_ms"]) + "†", ui.yellow)
                if r["bursty"]
                else (_ms(r["itl_p50_ms"]), mark(r["itl_p50_ms"], best_itl))
            ),
            core.fmt(r["tokens_per_chunk_median"]),
            (f"{ok}/{n}", ok_style),
            (core.fmt(r["price_out_per_1m"], 2), mark(r["price_out_per_1m"], cheapest)),
        ]
        if show_delta:
            if r is base:
                cells += [("base", ui.grey), ("base", ui.grey)]
            else:
                dt = r["ttft_p50_s"] - base["ttft_p50_s"] if r["ttft_p50_s"] is not None else None
                ds = (
                    (r["out_tps_p50"] - base["out_tps_p50"]) / base["out_tps_p50"] * 100
                    if r["out_tps_p50"] is not None
                    else None
                )
                cells += [
                    ("—", None) if dt is None else (f"{dt:+.2f}s", ui.red if dt > 0 else ui.green),
                    ("—", None) if ds is None else (f"{ds:+.0f}%", ui.red if ds < 0 else ui.green),
                ]
        table.append(cells)

    title = f"{prompt} · single stream" if conc == 1 else f"{prompt} · c={conc}"
    legend = "p50 · ttft first token · tok/s decode rate · itl gap between chunks"
    if estimated:
        legend += " · ≈ chars/4 estimate"
    if any(r["bursty"] for r in rows):
        legend += " · † chunks arrived in bursts"
    ui.say()
    ui.table(cols, table, title=title, footer=legend)
    for r in rows:
        for note in r["notes"]:
            first, *rest = _wrap(f"{r['target']}: {note}", ui.width - 6)
            ui.warn(first)
            for line in rest:
                ui.say("    " + line)


def print_load_table(ui: UI, summary: dict[str, Any], prompt: str) -> None:
    rows = [r for r in summary["rows"] if r["prompt"] == prompt and r["n"]]
    levels = sorted({int(c) for r in rows for c in r["by_concurrency"]})
    if ui.silent or len(levels) < 2:
        return
    low, high = levels[0], levels[-1]
    cols = (
        [Col("provider", "l")] + [Col(f"c={c}") for c in levels] + [Col("scaling", "l"), Col("ok")]
    )
    peak = max(
        (r["by_concurrency"].get(str(high), {}).get("aggregate_tps") or 0 for r in rows), default=0
    )
    table = []
    for r in rows:
        by = r["by_concurrency"]
        cells: list[Any] = [r["target"]]
        for c in levels:
            agg = by.get(str(c), {}).get("aggregate_tps")
            style = ui.best if c == high and agg and agg == peak and len(rows) > 1 else None
            cells.append((core.fmt(agg), style))
        lo_agg = by.get(str(low), {}).get("aggregate_tps")
        hi_agg = by.get(str(high), {}).get("aggregate_tps")
        if lo_agg and hi_agg:
            ratio = hi_agg / lo_agg
            efficiency = ratio / (high / low)
            if efficiency >= 0.6:
                cells.append((f"{ratio:.1f}× scales", ui.green))
            elif efficiency < 0.35:
                cells.append((f"{ratio:.1f}× queues", ui.yellow))
            else:
                cells.append((f"{ratio:.1f}× partial", None))
        else:
            cells.append(("—", None))
        ok = sum(by[str(c)]["ok"] for c in levels[1:] if str(c) in by)
        n = sum(by[str(c)]["n"] for c in levels[1:] if str(c) in by)
        cells.append((f"{ok}/{n}", ui.green if ok == n else ui.red if ok == 0 else ui.yellow))
        table.append(cells)
    ui.say()
    ui.table(
        cols,
        table,
        title=f"{prompt} · under load · aggregate tok/s",
        footer=f"all tokens in a batch ÷ its wall clock · scaling = c={high} vs c={low}",
    )


def print_rankings(ui: UI, summary: dict[str, Any], prompt: str) -> None:
    rows = [r for r in summary["rows"] if r["prompt"] == prompt and r["ok"]]
    if ui.silent or len(rows) < 2:
        return
    lines = []
    rated = [r for r in rows if r["out_tps_p50"] is not None and not _thinking(r)]
    if rated:
        fastest = max(rated, key=lambda r: r["out_tps_p50"])
        lines.append(("▲", "fastest", fastest["target"], f"{fastest['out_tps_p50']:.1f} tok/s"))
    timed = [r for r in rows if r["ttft_p50_s"] is not None]
    if timed:
        snappiest = min(timed, key=lambda r: r["ttft_p50_s"])
        lines.append(
            (
                "●",
                "snappiest",
                snappiest["target"],
                f"{snappiest['ttft_p50_s']:.2f}s to first token",
            )
        )
    priced = [r for r in rows if r["price_out_per_1m"] is not None]
    if priced:
        cheapest = min(priced, key=lambda r: r["price_out_per_1m"])
        lines.append(
            ("$", "cheapest", cheapest["target"], f"${cheapest['price_out_per_1m']:.2f} / 1M out")
        )
    width = max(len(name) for _i, _l, name, _d in lines)
    ui.say()
    for icon, label, name, detail in lines:
        ui.say(
            f"  {ui.cyan(icon)} {ui.grey(label.ljust(10))} {ui.bold(name.ljust(width))}  {detail}"
        )


def render_run(ui: UI, summary: dict[str, Any], prompts: list[str]) -> None:
    for prompt in prompts:
        print_run_table(ui, summary, prompt)
        print_load_table(ui, summary, prompt)
        print_rankings(ui, summary, prompt)


def _wrap(text: str, width: int) -> list[str]:
    import textwrap

    return textwrap.wrap(text, max(30, width), break_on_hyphens=False) or [""]


def print_fingerprint(
    ui: UI, summary: dict[str, Any], prints: list[core.Fingerprint], targets: list[str]
) -> None:
    if ui.silent:
        return
    by_key = {(f.target, f.prompt, f.rep): f for f in prints}
    prompt = summary["prompt_used"]
    present = [t for t in targets if t not in summary["no_data"]]
    group_of = {t: i for i, g in enumerate(summary["clusters"]) for t in g}

    if 2 <= len(present) <= 12:
        letters = "ABCDEFGHIJKL"
        name_w = min(26, max(len(t) for t in present))
        label_w = name_w + 4
        grid = label_w + 5 * len(present) + 1
        title = f" agreement · {prompt} · % identical tokens "
        plain = "■ ≥99  ■ 90–99  ■ 50–90  ■ <50  ■ self"
        # a two-target grid is narrower than its own title and legend
        width = max(grid, len(title) + 1, len(plain) + 2)
        ui.say()
        ui.say(ui.grey("╭─") + ui.bold(title) + ui.grey("─" * max(0, width - len(title) - 1) + "╮"))
        head = " " * label_w + "".join(f"{letters[i]:>4} " for i in range(len(present)))
        ui.say(ui.grey("│") + ui.dim(head.ljust(width)) + ui.grey("│"))
        for i, a_name in enumerate(present):
            label = f" {letters[i]}  {a_name[:name_w]:<{name_w}}"
            cells = []
            for b_name in present:
                if a_name == b_name:
                    cells.append(ui.heat(summary["self_agreement"].get(a_name), diagonal=True))
                    continue
                frac, _ = core.compare_prints(
                    by_key[(a_name, prompt, 0)], by_key[(b_name, prompt, 0)]
                )
                cells.append(ui.heat(frac))
            colour = ui.group(group_of.get(a_name, 0))
            pad = " " * (1 + width - grid)
            ui.say(ui.grey("│") + colour(label) + "".join(cells) + pad + ui.grey("│"))
        swatch = lambda code, text: ui.style("■", code) + " " + ui.grey(text)  # noqa: E731
        legend = "  ".join(
            [
                swatch("\033[38;5;28m", "≥99"),
                swatch("\033[38;5;178m", "90–99"),
                swatch("\033[38;5;130m", "50–90"),
                swatch("\033[38;5;88m", "<50"),
                swatch("\033[38;5;238m", "self"),
            ]
        )
        ui.say(ui.grey("├" + "─" * width + "┤"))
        ui.say(ui.grey("│") + " " + legend + " " * max(0, width - len(plain) - 1) + ui.grey("│"))
        ui.say(ui.grey("╰" + "─" * width + "╯"))

    ui.say()
    tokens = {}
    for target, count in summary["prompt_tokens"].items():
        if count is not None:  # the input's count, valid even if the reply failed
            tokens.setdefault(count, []).append(target)
    if len(tokens) > 1:
        ui.warn(f"tokenizer: {len(tokens)} different prompt-token counts for the same input")
        for count, names in sorted(tokens.items()):
            for i, line in enumerate(_wrap(", ".join(names), ui.width - 20)):
                ui.say(f"      {ui.grey(f'{count:>5} tok' if i == 0 else ' ' * 9)}  {line}")

    noisy = set(summary["noisy"])
    unweighed = noisy | set(summary["unmeasured"])
    digits = len(str(max((len(g) for g in summary["clusters"]), default=1)))
    for index, group in enumerate(summary["clusters"]):
        colour = ui.group(index)
        tag = (
            " (no deterministic noise floor — can't be placed)"
            if all(t in unweighed for t in group)
            else ""
        )
        lines = _wrap(", ".join(group) + tag, ui.width - 22)
        label = f"group {index + 1}"
        count = ui.grey(f"({len(group):>{digits}})")
        ui.say(f"  {colour('●')} {ui.bold(label)}  {count}  {lines[0]}")
        for line in lines[1:]:
            ui.say(" " * (17 + digits) + line)
    for target, error in summary["no_data"].items():
        ui.say(
            f"  {ui.grey('○')} {ui.grey('no data')}  {target} {ui.grey('— ' + error.split(':')[0])}"
        )
    for target in summary["noisy"]:
        value = summary["self_agreement"].get(target, 0)
        ui.say(
            f"  {ui.yellow('~')} {ui.grey('noisy')}    {target} {ui.grey(f'— self-agreement {value * 100:.0f}%')}"
        )
    if summary["noise_floor_measured"]:
        for target in summary["unmeasured"]:
            ui.say(
                f"  {ui.yellow('?')} {ui.grey('no floor')} {target} {ui.grey('— second rep failed; not weighed')}"
            )
    else:
        ui.warn("noise floor not measured — needs two successful reps per provider (--reps 2)")

    ui.say()
    verdict = summary["verdict"]
    if verdict == "split":
        firm = summary["distinguishable_groups"]
        ui.say(
            f"  {ui.badge('SPLIT', 'warn')} {firm} distinguishable groups — not the same artifact."
        )
        ui.hint("          Run a task eval before treating them as equivalent.")
    elif verdict == "consistent":
        ui.say(
            f"  {ui.badge('CONSISTENT', 'ok')} indistinguishable at this resolution — "
            "consistent with the same weights."
        )
    else:
        ui.say(
            f"  {ui.badge('INCONCLUSIVE', 'muted')} fewer than two providers with a measured, "
            "deterministic noise floor."
        )


# --------------------------------------------------------------------------
# commands
# --------------------------------------------------------------------------


def cmd_doctor(args: argparse.Namespace, ui: UI) -> dict[str, Any]:
    checks: list[dict[str, Any]] = []

    def add(name: str, ok: bool, detail: str, critical: bool = True) -> None:
        checks.append({"check": name, "ok": ok, "detail": detail, "critical": critical})

    add("python", sys.version_info >= (3, 11), sys.version.split()[0] + " (need 3.11+)")
    try:
        import httpx

        add("httpx", True, httpx.__version__)
    except ImportError as exc:  # pragma: no cover
        add("httpx", False, str(exc))
        httpx = None  # type: ignore

    add(
        "http2",
        core.HTTP2,
        "h2 installed" if core.HTTP2 else 'optional — pip install "httpx[http2]"',
        critical=False,
    )

    config_path = None
    cfg = None
    try:
        config_path = resolve_config(args.config)
        cfg = core.load_config(config_path)
        add("config", True, f"{config_path} · {len(cfg.targets)} targets")
    except core.TpsError as exc:
        add("config", False, str(exc))

    mock_only = bool(cfg and all(t.mock is not None for t in cfg.targets))
    if cfg:
        missing = [t for t in cfg.targets if t.needs_key()]
        if mock_only:
            detail = "not needed — mock-only config (use --mock)"
        elif missing:
            envs = sorted({t.api_key_env for t in missing if t.api_key_env})
            detail = (
                f"missing for {len(missing)} target(s): {', '.join(t.name for t in missing[:4])}"
            )
            detail += f"{' …' if len(missing) > 4 else ''}" + (
                f" — set {', '.join(envs)}" if envs else ""
            )
        else:
            detail = "all set"
        add("credentials", mock_only or not missing, detail)

        if args.network and httpx is not None:

            async def probe() -> list[tuple[str, str]]:
                async with httpx.AsyncClient(
                    timeout=httpx.Timeout(5.0), follow_redirects=True
                ) as client:

                    async def one(target: core.Target) -> tuple[str, str]:
                        try:
                            response = await client.get(target.base_url)
                            return target.name, f"HTTP {response.status_code}"
                        except Exception as exc:  # noqa: BLE001 - report, never crash
                            return target.name, type(exc).__name__

                    return await asyncio.gather(*(one(t) for t in cfg.targets))

            for name, detail in asyncio.run(probe()):
                # any HTTP status means the host answered; exceptions mean it didn't
                add(f"reach {name}", detail.startswith("HTTP"), detail, critical=False)

    failed = [c for c in checks if c["critical"] and not c["ok"]]
    if not failed:
        exit_code = 0
    elif all(c["check"] == "credentials" for c in failed):
        exit_code = 2
    else:
        exit_code = 1

    ui.header("doctor", "environment · config · credentials")
    ui.say()
    width = max(len(c["check"]) for c in checks) + 3
    for item in checks:
        line = ui.kv(item["check"], item["detail"], width)
        if item["ok"]:
            ui.ok(line)
        elif item["critical"]:
            ui.fail(line)
        else:
            ui.warn(line)
    ui.say()
    if not failed:
        run = f"tps run -c {config_path}" + (" --mock" if mock_only else "")
        ui.say(f"  {ui.green(ui.bold('Ready.'))} {ui.grey('next →')} {run}")
    else:
        ui.say(ui.grey("  Fix the ✗ rows above, then re-run `tps doctor`."))
    return {"command": "doctor", "ok": not failed, "checks": checks, "exit_code": exit_code}


def cmd_init(args: argparse.Namespace, ui: UI) -> dict[str, Any]:
    out = args.out
    if out.exists() and not args.force:
        raise core.UsageError(f"{out} exists — pass --force to overwrite")

    text = endpoint_config(args.endpoint_url, args, "--endpoint")
    ui.header("init")
    ui.say()
    if text is not None:
        url = core.redact_url(core.config_from_text(text, "--endpoint").targets[0].base_url)
        out.write_text(text, encoding="utf-8")
        ui.ok(f"wrote {ui.bold(str(out))} — 1 target: {args.model} at {url}")
        export = f"export {args.api_key_env}=… && " if args.api_key_env else ""
        ui.hint(f"  next → {export}tps run -c {out} --dry-run   (then without --dry-run)")
        return {
            "command": "init",
            "ok": True,
            "config": str(out),
            "model": args.model,
            "targets": 1,
            "endpoint": url,
        }
    if args.model:
        canonical, endpoints, _payload = core.fetch_endpoints(
            args.model, os.environ.get("OPENROUTER_API_KEY")
        )
        text, count, collapsed = core.targets_toml(canonical, endpoints)
        out.write_text(text, encoding="utf-8")
        note = f" ({collapsed} duplicate endpoint(s) collapsed)" if collapsed else ""
        ui.ok(f"wrote {ui.bold(str(out))} — {count} pinned targets for {canonical}{note}")
        ui.hint(f"  next → export OPENROUTER_API_KEY=… && tps run -c {out}")
        return {
            "command": "init",
            "ok": True,
            "config": str(out),
            "model": canonical,
            "targets": count,
        }

    out.write_text(STARTER_CONFIG, encoding="utf-8")
    ui.ok(f"wrote {ui.bold(str(out))} (starter template)")
    ui.hint(f"  next → edit the targets, then: tps doctor && tps run -c {out}")
    ui.hint("  or generate one: tps init --endpoint URL --model ID --api-key-env VAR --force")
    ui.hint(
        "               or: tps init --model deepseek/deepseek-v4.1-flash --force  (OpenRouter)"
    )
    return {"command": "init", "ok": True, "config": str(out), "model": None, "targets": 0}


QUANT_STYLE = {"fp4": "magenta", "fp6": "magenta", "fp8": "cyan", "bf16": "green", "fp16": "green"}


def cmd_discover(args: argparse.Namespace, ui: UI) -> dict[str, Any]:
    canonical, endpoints, payload = core.fetch_endpoints(
        args.model, args.api_key or os.environ.get("OPENROUTER_API_KEY"), args.from_json
    )
    rows = core.normalize_endpoints(endpoints)
    if args.json_out:
        args.json_out.write_text(json.dumps(payload, indent=2), encoding="utf-8")

    ui.header("discover", f"{canonical} · {len(endpoints)} endpoints")
    shown = sorted(rows, key=lambda r: (r["price_out_per_1m"] is None, r["price_out_per_1m"] or 0))
    peak = max((r["price_out_per_1m"] or 0 for r in rows), default=0)
    cheapest = _best(rows, lambda r: r["price_out_per_1m"], lowest=True)
    table = []
    for row in shown:
        quant = row["quantization"] or "—"
        style = getattr(ui, QUANT_STYLE.get(str(quant).lower(), "grey"))
        price_out = row["price_out_per_1m"]
        table.append(
            [
                row["provider"] or "—",
                (row["tag"] or row["slug"], ui.grey),
                (quant, style),
                core.fmt(row["price_in_per_1m"], 3),
                (
                    core.fmt(price_out, 3),
                    ui.best if cheapest is not None and price_out == cheapest else None,
                ),
                Bar(price_out, peak, 16, ui.cyan),
                f"{row['context_length'] // 1000}k" if row["context_length"] else "—",
            ]
        )
    ui.say()
    ui.table(
        [
            Col("provider", "l"),
            Col("pin", "l"),
            Col("quant", "l"),
            Col("$/1M in"),
            Col("$/1M out"),
            Col("", "l", flex=True),
            Col("ctx", drop=1),
        ],
        table,
        title=f"{canonical} · sorted by output price",
        footer="prices per 1M tokens from OpenRouter · quantization as reported by the provider",
    )

    written = None
    count = 0
    if args.out:
        text, count, collapsed = core.targets_toml(canonical, endpoints)
        args.out.write_text(text, encoding="utf-8")
        written = str(args.out)
        ui.say()
        ui.ok(f"wrote {ui.bold(written)} — {count} pinned targets")
        if collapsed:
            ui.hint(f"  {collapsed} duplicate endpoint(s) collapsed into the same pin")
        ui.hint(f"  next → tps run -c {written}")
    return {
        "command": "discover",
        "ok": True,
        "model": canonical,
        "endpoints": rows,
        "config": written,
        "targets": count,
    }


def _n(count: int, noun: str) -> str:
    return f"{count} {noun}{'' if count == 1 else 's'}"


def _models_label(cfg: core.RunConfig) -> str:
    models = list(dict.fromkeys(t.model for t in cfg.targets))
    return models[0] if len(models) == 1 else f"{len(models)} model ids"


def _k(tokens: int) -> str:
    return f"{tokens / 1000:.1f}k" if tokens >= 1000 else str(tokens)


def run_plan(
    ui: UI, cfg: core.RunConfig, path: Path | None, args: argparse.Namespace
) -> dict[str, Any]:
    """`tps run --dry-run`: the bill before the run. Nothing is sent."""
    plan = core.plan_run(cfg, mock=args.mock)
    missing = [] if args.mock else [t.name for t in cfg.targets if t.needs_key()]
    ui.header("run", f"{_models_label(cfg)} · dry run", mock=args.mock)
    ui.hint(
        f"  {_n(len(cfg.targets), 'target')} · {_n(len(cfg.prompts), 'prompt')} · "
        f"{_n(cfg.reps, 'rep')} · concurrency {','.join(map(str, cfg.concurrency))}"
    )
    ui.say()
    width = 12
    ui.say(
        "  "
        + ui.kv(
            "requests",
            f"{plan['requests']} ({plan['measured_requests']} measured + "
            f"{plan['warmup_requests']} warm-up)",
            width,
        )
    )
    ui.say(
        "  "
        + ui.kv(
            "tokens",
            f"≈{_k(plan['in_tokens_est'])} in (≤{_k(plan['in_tokens_max'])} by bytes) · "
            f"≤{_k(plan['out_tokens_max'])} out (max_tokens cap)",
            width,
        )
    )
    if args.mock:
        cost = "$0 — --mock sends nothing"
    elif plan["cost_max_usd"] is None:
        cost = "unknown — no target has a price (price = { … } or --price)"
    else:
        spend = plan["cost_max_usd"]
        cost = f"≤ ${spend:.4f}" if spend < 1 else f"≤ ${spend:,.2f}"
        if plan["unpriced"]:
            cost += f" + unpriced: {', '.join(plan['unpriced'])}"
    ui.say("  " + ui.kv("cost", cost, width))
    assumed = plan["assumed"]
    ui.say(
        "  "
        + ui.kv(
            "time",
            f"≈{plan['est_minutes']:g} min at an assumed {assumed['tok_s']:g} tok/s and "
            f"{assumed['ttft_s']:g}s TTFT",
            width,
        )
    )
    if missing:
        names = ", ".join(missing[:4]) + (f" +{len(missing) - 4} more" if len(missing) > 4 else "")
        ui.say()
        ui.warn(f"missing credentials for {names} — the real run would exit 2")
    ui.say()
    ui.hint("  nothing was sent · drop --dry-run to run it")
    return {
        "command": "run",
        "ok": True,
        "dry_run": True,
        "mock": args.mock,
        "config": str(path) if path else None,
        "model": cfg.targets[0].model,
        "reps": cfg.reps,
        "concurrency": cfg.concurrency,
        "prompts": list(cfg.prompts),
        "plan": plan,
        "missing_credentials": missing,
    }


def cmd_run(args: argparse.Namespace, ui: UI) -> dict[str, Any]:
    if args.config and (args.endpoint_url or args.api):
        raise core.UsageError("pass either -c FILE or --base-url/--api, not both")
    text = endpoint_config(args.endpoint_url, args, "--base-url")
    if text is None:
        path: Path | None = resolve_config(args.config)
        cfg = core.load_config(path)
    else:
        path = None
        cfg = core.config_from_text(text, "--base-url")
    apply_overrides(cfg, args)
    check_mock(cfg, path or Path("--base-url"), args.mock, ui)
    if args.dry_run:
        return run_plan(ui, cfg, path, args)
    if not args.mock:
        require_keys(cfg)

    outdir = args.out or Path("runs") / stamp()
    if text is not None:
        # Keep the run as a config next to its results — with the settings it
        # actually ran with (--reps, --max-tokens, …), so `-c` repeats it.
        text = endpoint_config(args.endpoint_url, args, "--base-url", core.run_toml(cfg))
        path = outdir / "targets.toml"
        if path.exists() and path.read_text(encoding="utf-8") != text:
            # `-o .` next to a hand-written (or hand-edited) config must never
            # replace it
            raise core.UsageError(
                f"{path} already exists and isn't this run's config — pick another -o"
            )
        outdir.mkdir(parents=True, exist_ok=True)
        path.write_text(text, encoding="utf-8")
    total = core.planned_requests(cfg)
    ui.header("run", _models_label(cfg), mock=args.mock)
    ui.hint(
        f"  {_n(len(cfg.targets), 'target')} · {_n(len(cfg.prompts), 'prompt')} · {_n(cfg.reps, 'rep')} · "
        f"concurrency {','.join(map(str, cfg.concurrency))} · {total} requests"
    )
    if cfg.reps < 7:
        ui.warn(f"{cfg.reps} reps — differences under ~15% are noise at this sample size")

    with Progress(ui, total, "warming up") as progress:

        def on_batch(**kw: Any) -> None:
            if kw["phase"] == "warmup":
                label = f"warm-up · {kw['target']}"
            else:
                label = f"{kw['target']} · c={kw['concurrency']} · rep {kw['rep'] + 1}/{cfg.reps}"
            progress.update(kw["done"], label)

        try:
            samples = asyncio.run(core.execute(cfg, outdir, args.mock, on_batch=on_batch))
        except KeyboardInterrupt:
            progress.close()
            kept = 0
            try:
                partial, meta = core.load_samples(outdir)
                kept = sum(1 for s in partial if not core.is_warmup(s))
                if kept:
                    core.write_report(outdir, partial, meta)
            except core.TpsError:
                pass
            raise Interrupted(
                f"interrupted — {kept} measured request(s) kept in {outdir}"
                + (f"; partial report at {outdir}/report.md" if kept else "")
            ) from None

    meta = json.loads((outdir / "meta.json").read_text(encoding="utf-8"))
    rows = [s.as_dict() for s in samples]
    core.write_report(outdir, rows, meta)
    summary = summarise(rows, meta)
    render_run(ui, summary, list(cfg.prompts))

    measured = [s for s in samples if s.phase != "warmup"]
    failed = sum(1 for s in measured if not s.ok)
    ui.say()
    if failed:
        ui.warn(f"{failed}/{len(measured)} requests failed — see Failures in the report")
    ui.ok(f"wrote {ui.bold(f'{outdir}/report.md')}  {ui.grey('· summary.csv · raw.jsonl')}")
    ui.hint(
        f"  next → tps report {outdir}   ·   tps fingerprint -c {path}"
        + (" --mock" if args.mock else "")
    )

    return {
        "command": "run",
        "ok": failed < len(measured),
        "mock": args.mock,
        "run_dir": str(outdir),
        "config": str(path),
        "model": next((t["model"] for t in meta["targets"]), None),
        "reps": cfg.reps,
        "concurrency": cfg.concurrency,
        "results": summary["rows"],
        "failed": failed,
        # `total` is measured requests only; raw.jsonl also holds the warm-ups
        "total": len(measured),
        "warmup_requests": len(samples) - len(measured),
        "planned_requests": core.planned_requests(cfg),
        # partial failure is data, not a usage error: it shows up in `failed`
        "exit_code": 4 if measured and failed == len(measured) else 0,
        "artifacts": {
            "report": str(outdir / "report.md"),
            "csv": str(outdir / "summary.csv"),
            "raw": str(outdir / "raw.jsonl"),
        },
    }


def cmd_report(args: argparse.Namespace, ui: UI) -> dict[str, Any]:
    samples, meta = core.load_samples(args.run_dir)
    text = core.write_report(args.run_dir, samples, meta)
    if args.markdown:
        if not args.json:
            print(text)
        return {"command": "report", "ok": True, "run_dir": str(args.run_dir), "report": text}

    flags = " · partial" if meta.get("complete") is False else ""
    model = next((t.get("model") for t in meta.get("targets", []) if t.get("model")), "?")
    ui.header(
        "report",
        f"{args.run_dir} · {model} · {meta.get('created', '?')}{flags}",
        mock=bool(meta.get("mock")),
    )
    summary = summarise(samples, meta)
    prompts = list(dict.fromkeys(r["prompt"] for r in summary["rows"]))
    render_run(ui, summary, prompts)
    ui.say()
    ui.ok(f"rewrote {ui.bold(f'{args.run_dir}/report.md')}  {ui.grey('· summary.csv')}")
    return {"command": "report", "ok": True, "run_dir": str(args.run_dir), "report": text}


def cmd_fingerprint(args: argparse.Namespace, ui: UI) -> dict[str, Any]:
    path = resolve_config(args.config)
    cfg = core.load_config(path)
    for flag, value in (
        ("--reps", args.reps),
        ("--prompt-count", args.prompt_count),
        ("--max-tokens", args.max_tokens),
    ):
        if value < 1:
            raise core.UsageError(f"{flag} must be at least 1 (got {value})")
    if args.timeout is not None:
        cfg.timeout_s = args.timeout
        core.validate(cfg, "flags")
    check_mock(cfg, path, args.mock, ui)
    if not args.mock:
        require_keys(cfg)
    outdir = args.out or Path("runs") / f"{stamp()}-fingerprint"
    prompt_count = min(args.prompt_count, len(cfg.prompts))
    total = prompt_count * args.reps * len(cfg.targets)
    ui.header("fingerprint", _models_label(cfg), mock=args.mock)
    claude = [t.name for t in cfg.targets if t.api == "anthropic"]
    decoding = "greedy" if not claude else "greedy where allowed (Claude API: sampled)"
    ui.hint(
        f"  {_n(len(cfg.targets), 'target')} · {_n(prompt_count, 'prompt')} · {_n(args.reps, 'rep')} · "
        f"{decoding}, {args.max_tokens} tokens · {total} requests"
    )

    with Progress(ui, total) as progress:
        try:
            report, prints, summary = core.run_fingerprint(
                cfg,
                outdir,
                args.max_tokens,
                args.reps,
                prompt_count,
                args.mock,
                on_progress=lambda **kw: progress.update(
                    kw["done"], f"{kw['target']} · {kw['prompt']} · rep {kw['rep'] + 1}"
                ),
            )
        except KeyboardInterrupt:
            progress.close()
            path = outdir / "fingerprints.jsonl"
            kept = len(path.read_text().splitlines()) if path.exists() else 0
            raise Interrupted(
                f"interrupted — {kept} fingerprint(s) kept in {outdir}"
                + (f"; partial report at {outdir}/fingerprint.md" if kept else "")
            ) from None

    targets = [t.name for t in cfg.targets]
    print_fingerprint(ui, summary, prints, targets)
    ui.say()
    ui.ok(f"wrote {ui.bold(f'{outdir}/fingerprint.md')}  {ui.grey('· fingerprints.jsonl')}")

    any_ok = any(p.ok for p in prints)
    return {
        "command": "fingerprint",
        "ok": any_ok,
        "mock": args.mock,
        "run_dir": str(outdir),
        "report": report,
        **summary,
        "exit_code": 0 if any_ok else 4,
    }


# --------------------------------------------------------------------------
# parser
# --------------------------------------------------------------------------


def build_parser() -> argparse.ArgumentParser:
    parser = Parser(
        prog="tps",
        description="Measure one model across many providers and gateways.",
        epilog=(
            "examples:\n"
            "  tps run -c targets.mock.toml --mock        # 2-second offline demo\n"
            "  tps init --model deepseek/deepseek-v4.1-flash\n"
            "  tps doctor\n"
            "  tps run -c targets.toml --reps 7 --concurrency 1,4\n"
            "  tps fingerprint -c targets.toml\n"
            "\ndocs: https://github.com/teal-sea/tpsbench/tree/main/docs"
        ),
        formatter_class=argparse.RawDescriptionHelpFormatter,
    )
    parser.add_argument("--version", action="version", version=f"tps {__version__}")
    parser.add_argument("--json", action="store_true", help="machine-readable output on stdout")
    parser.add_argument("--no-color", action="store_true", help="disable ANSI colour")
    parser.add_argument("-q", "--quiet", action="store_true", help="only errors")
    parser.add_argument("-v", "--verbose", action="store_true", help="tracebacks on failure")
    sub = parser.add_subparsers(dest="command", metavar="<command>")

    def common(p: argparse.ArgumentParser) -> None:
        # mirrored on subcommands so `tps run --json` works as well as `tps --json run`
        p.add_argument("--json", action="store_true", default=argparse.SUPPRESS)
        p.add_argument("--no-color", action="store_true", default=argparse.SUPPRESS)
        p.add_argument("-q", "--quiet", action="store_true", default=argparse.SUPPRESS)
        p.add_argument("-v", "--verbose", action="store_true", default=argparse.SUPPRESS)

    def endpoint_flags(p: argparse.ArgumentParser, flag: str) -> None:
        p.add_argument(
            flag,
            dest="endpoint_url",
            default=None,
            metavar="URL",
            help="any OpenAI-compatible base URL, e.g. https://api.example.com/v1 — no config file",
        )
        p.add_argument(
            "--model",
            default=None,
            help=(
                "model id at that endpoint"
                if flag == "--base-url"
                else f"with {flag}: the model id there; alone: OpenRouter slug to discover"
            ),
        )
        p.add_argument(
            "--api",
            choices=core.APIS,
            default=None,
            help=f"wire format (default openai); anthropic = native Claude API, {CLAUDE_API_URL} "
            "unless a URL is given — accepts API keys and Claude subscription tokens",
        )
        p.add_argument("--api-key-env", default=None, help="env var holding the key")
        p.add_argument("--name", default=None, help="target name (default: the host)")
        p.add_argument("--price", default=None, metavar="IN,OUT", help="USD per 1M tokens")

    p_doctor = sub.add_parser("doctor", help="check environment, config and credentials")
    p_doctor.add_argument("-c", "--config", type=Path, default=None)
    p_doctor.add_argument("--network", action="store_true", help="also probe base URLs")
    common(p_doctor)

    p_init = sub.add_parser("init", help="scaffold a config")
    endpoint_flags(p_init, "--endpoint")
    p_init.add_argument("--out", type=Path, default=Path("targets.toml"))
    p_init.add_argument("--force", action="store_true")
    common(p_init)

    p_disc = sub.add_parser("discover", help="list providers serving a model, with prices")
    p_disc.add_argument("model", help="e.g. deepseek/deepseek-v4.1-flash")
    p_disc.add_argument("--out", type=Path, default=None, help="write a config")
    p_disc.add_argument("--api-key", default=None)
    p_disc.add_argument("--from-json", type=Path, default=None, help="offline: recorded response")
    p_disc.add_argument("--json-out", type=Path, default=None, help="save the raw API payload")
    common(p_disc)

    p_run = sub.add_parser("run", help="measure throughput and latency")
    p_run.add_argument("-c", "--config", type=Path, default=None)
    p_run.add_argument("-o", "--out", type=Path, default=None)
    p_run.add_argument(
        "--dry-run", action="store_true", help="print requests, tokens, cost and time; send nothing"
    )
    endpoint_flags(p_run, "--base-url")
    p_run.add_argument("--reps", type=int, default=None)
    p_run.add_argument("--concurrency", default=None, help="e.g. 1,4,16")
    p_run.add_argument("--prompts", default=None, help="comma separated prompt names")
    p_run.add_argument(
        "--max-tokens", type=int, default=None, help="override every prompt's max_tokens"
    )
    p_run.add_argument(
        "--temperature",
        default=None,
        help='a number, or "omit" to not send it (default: 0; not sent to the Claude API)',
    )
    p_run.add_argument("--timeout", type=float, default=None, help="per-request timeout, seconds")
    p_run.add_argument("--mock", action="store_true", help="synthetic numbers, no network")
    p_run.add_argument("--no-warmup", action="store_true")
    common(p_run)

    p_rep = sub.add_parser("report", help="re-render a previous run")
    p_rep.add_argument("run_dir", type=Path)
    p_rep.add_argument("--markdown", action="store_true", help="print report.md instead of tables")
    common(p_rep)

    p_fp = sub.add_parser("fingerprint", help="test whether targets serve the same weights")
    p_fp.add_argument("-c", "--config", type=Path, default=None)
    p_fp.add_argument("-o", "--out", type=Path, default=None)
    p_fp.add_argument("--max-tokens", type=int, default=160)
    p_fp.add_argument("--reps", type=int, default=2)
    p_fp.add_argument("--prompt-count", type=int, default=2, help="how many prompts to probe")
    p_fp.add_argument("--timeout", type=float, default=None, help="per-request timeout, seconds")
    p_fp.add_argument("--mock", action="store_true", help="synthetic fingerprints, no network")
    common(p_fp)

    return parser


COMMANDS = {
    "doctor": cmd_doctor,
    "init": cmd_init,
    "discover": cmd_discover,
    "run": cmd_run,
    "report": cmd_report,
    "fingerprint": cmd_fingerprint,
}


def _safe_streams() -> None:
    """Never crash on a legacy console encoding: degrade glyphs instead."""
    for stream in (sys.stdout, sys.stderr):
        try:
            stream.reconfigure(errors="replace")  # type: ignore[union-attr]
        except (AttributeError, ValueError):
            pass


def _error_payload(command: str | None, code: int, message: str) -> dict[str, Any]:
    return {
        "schema_version": SCHEMA_VERSION,
        "command": command,
        "ok": False,
        "error": {"code": code, "message": message},
    }


def main(argv: list[str] | None = None) -> int:
    try:
        return _main(argv)
    except BrokenPipeError:
        # stdout closed early (`tps … | head`): stop quietly, like other CLIs
        try:
            os.dup2(os.open(os.devnull, os.O_WRONLY), sys.stdout.fileno())
        except OSError:
            pass
        return 141


def _main(argv: list[str] | None) -> int:
    argv = sys.argv[1:] if argv is None else list(argv)
    _safe_streams()
    parser = build_parser()
    want_json = "--json" in argv
    command = next((a for a in argv if a in COMMANDS), None)
    captured = io.StringIO()
    try:
        # in --json mode, --help/--version text is wrapped in the one JSON object
        with contextlib.redirect_stdout(captured) if want_json else contextlib.nullcontext():
            args = parser.parse_args(argv)
    except core.UsageError as exc:
        ui = UI(json_mode=want_json, color=False if "--no-color" in argv else None)
        if want_json:
            ui.emit(_error_payload(command, exc.exit_code, str(exc)))
        else:
            ui.error(str(exc))
        return exc.exit_code
    except SystemExit as exc:  # --help / --version
        if want_json:
            payload: dict[str, Any] = {
                "schema_version": SCHEMA_VERSION,
                "command": command,
                "ok": True,
            }
            if "--version" in argv:
                payload["version"] = __version__
            else:
                payload["help"] = captured.getvalue()
            UI(json_mode=True).emit(payload)
        return int(exc.code or 0)

    if not args.command:
        if args.json:
            UI(json_mode=True).emit(_error_payload(None, 1, "no command given — see `tps --help`"))
            return 1
        parser.print_help()
        return 0

    ui = UI(
        json_mode=args.json,
        color=False if args.no_color else None,
        quiet=args.quiet,
    )
    handler = COMMANDS[args.command]

    try:
        payload = handler(args, ui)
        if args.json:
            ui.emit({"schema_version": SCHEMA_VERSION, **payload})
        return int(payload.get("exit_code", 0))
    except core.TpsError as exc:
        if args.json:
            ui.emit(_error_payload(args.command, exc.exit_code, str(exc)))
        else:
            ui.error(str(exc))
        return exc.exit_code
    except BrokenPipeError:
        raise
    except KeyboardInterrupt:
        if args.json:
            ui.emit(_error_payload(args.command, 130, "interrupted"))
        else:
            print("", file=sys.stderr)
        return 130
    except Exception as exc:  # noqa: BLE001 - last resort, keep it readable
        if args.json:
            ui.emit(_error_payload(args.command, 1, f"{type(exc).__name__}: {exc}"))
        elif args.verbose:
            raise
        else:
            ui.error(f"{type(exc).__name__}: {exc}", hint="re-run with -v for a traceback")
        return 1


if __name__ == "__main__":
    raise SystemExit(main())
