"""MCP server exposing the decision-confidence meta-layer.

Reference implementation, stdio transport. It is a **pure transform** of what
the caller supplies: no network calls, no API keys, no chain reads. Fetching
from the underlying risk vendors — and everything that comes with it
(credentials, rate limits, caching, PII policy) — stays with the host.

Three axes, and they are separate tools on purpose. ``decision_confidence``
discounts evidence **across sources** and takes a subject plus vendor payloads.
``knowledge_window`` discounts it **across time** and takes three dates and a
trial count; ``track_record`` does the same for a record with no model behind
it, split at the day it was picked. ``counterfactual_audit`` discounts it **across inputs** and takes a
list of perturbations. A subject, a backtest and an agent's responsiveness are
three different objects, so folding any of them together would be exactly the
category error this library exists to catch. An agent reads them separately;
no answer needs the others.

``trace_audit`` is the one tool that reads a file: an agent transcript, named
by path, read-only. A transcript runs to hundreds of megabytes, so passing it
inline is not an option; nothing is written and nothing leaves the machine.

``hyperliquid_wallet`` is the one tool that makes a network call: it reads a
wallet's public portfolio history from Hyperliquid's info API (no key, nothing
sent but the address) and scores it the way evidencedeflator.com/wallet/ does.

Run directly::

    python src/mcp_server.py

or, once installed with the optional extra (``pip install -e ".[mcp]"``)::

    decision-confidence-mcp

Requires the ``mcp`` package; the core library in ``decision_confidence.py``
and ``normalize.py`` remains dependency-free.
"""

from __future__ import annotations

import os
import sys
from datetime import datetime, timezone
from typing import Any, Dict, List, Optional

# Support running the file directly from a checkout, not just as an installed
# module.
sys.path.insert(0, os.path.dirname(os.path.abspath(__file__)))

from adapters import observe_vendor, supported_vendors  # noqa: E402
from decision_confidence import build_report  # noqa: E402
from counterfactual import (  # noqa: E402
    Perturbation, minimum_perturbations, perturbation_audit,
)
from counterfactual import remedies as cf_remedies  # noqa: E402
from effective_window import effective_window, remedies  # noqa: E402
from track_record import track_record as _track_record  # noqa: E402
import trial_count  # noqa: E402
import trace_audit as _trace_audit  # noqa: E402
import hl_wallet  # noqa: E402

SOURCE = "Hyperliquid public info API, portfolio allTime (accountValueHistory, pnlHistory)"

try:
    from mcp.server.fastmcp import FastMCP
except ImportError as exc:  # pragma: no cover - dependency guard
    raise SystemExit(
        "The MCP server needs the 'mcp' package: pip install \"evidence-deflator[mcp]\" (or pip install -e \".[mcp]\" from a checkout)"
    ) from exc


mcp = FastMCP("evidence-deflator")


@mcp.tool()
def decision_confidence(
    subject: str,
    sources: List[Dict[str, Any]],
    weights: Optional[Dict[str, float]] = None,
) -> Dict[str, Any]:
    """Combine several risk-source readings into one decision report.

    Use when more than one external risk source has been consulted about the
    same subject and the agent needs a single, auditable read on how much to
    trust the combination — especially when the sources may disagree.

    Args:
        subject: What is being assessed (token address, symbol, account —
            caller-defined; treated as an opaque label).
        sources: One entry per source,
            ``{"source_id": str, "raw": object, "vendor": str?}``. ``raw`` is
            the vendor payload exactly as received. When ``vendor`` names a
            registered adapter (call ``list_supported_vendors``) the payload is
            parsed with that vendor's real field names, and one payload may
            produce several observations covering different risk constructs.
            Without ``vendor``, generic shapes are recognised by their keys:
            ``{"fraud_probability": 0.0-1.0}``, ``{"tier": "LOW|MEDIUM|HIGH"}``,
            ``{"score": 0-100, "scale": "safety_0_100"}`` (flipped to risk),
            or ``{"score": 0-100}`` (already risk). Unrecognised or malformed
            payloads are marked as such and lower confidence — they are never
            guessed at.
        weights: Optional per-source weight keyed by ``source_id``. Weights
            apply *within* a construct; sources default to equal weight and a
            weight of 0 drops a source.

    Returns:
        A decision report. **Read ``constructs`` first** — it is one entry per
        thing actually measured, each with the only average that compares like
        with like, plus the within-construct ``spread`` and how many of its
        sources were usable.

        ``composite`` is a single 0-100 risk value (0 = safe, 100 = maximum
        risk) **only when every usable source measures the same construct**.
        When they do not, ``composite`` is ``null`` and ``verdict`` is
        ``not_comparable``: averaging a honeypot simulation with a contract-
        authority scan is a category error, not a noisy estimate, and no
        weighting fixes it. The old blended number is still reachable as
        ``blended_composite_unsafe`` — the name is the warning.

        Also returned: ``confidence`` (high/medium/low — evidence quality, not
        probability of correctness; capped at medium when a construct has no
        usable source at all, because ``unavailable`` is not ``safe``),
        ``contradictions``, and an ``audit`` trail that makes the result
        reconstructible without re-fetching.

        ``contradictions`` of kind ``range`` and ``polarity`` are raised only
        between sources sharing a construct — sources answering different
        questions cannot contradict each other. The split itself appears once
        as an ``info``-severity ``construct_mismatch``, which does **not**
        lower confidence.
    """
    observations = []
    for entry in sources:
        if not isinstance(entry, dict):
            continue
        source_id = str(entry.get("source_id") or f"source_{len(observations) + 1}")
        vendor = entry.get("vendor")
        raw = entry.get("raw")
        observations.extend(observe_vendor(
            str(vendor) if vendor else None,
            source_id,
            subject,
            raw if isinstance(raw, dict) else {},
        ))

    report = build_report(subject, observations, weights)
    return report.to_dict()


@mcp.tool()
def knowledge_window(
    cutoff: str,
    start: str,
    end: str,
    target_sharpe: float = 1.0,
    t_threshold: float = 2.0,
    trials: Optional[int] = None,
    trial_grid: Optional[Dict[str, int]] = None,
    effective_trials: Optional[float] = None,
    cutoff_source: Optional[str] = None,
    lang: str = "en",
) -> Dict[str, Any]:
    """Check whether a backtest could have told anyone anything, before trusting it.

    Call this **before quoting or acting on any backtest number** — a Sharpe, a
    return, a hit rate — that came out of a historical simulation run by, or
    evaluated with, a language model. It is pure arithmetic on dates and a
    count: it needs no price series and no returns, so it can be run before the
    performance figures even exist, and it disqualifies a result on grounds that
    no amount of good performance repairs.

    Two things get charged against a backtest:

    1. **What the model already read.** A model with a knowledge cutoff has seen
       what happened before that date. Months of the backtest lying before the
       cutoff do not test whether a strategy works; they test whether the model
       remembers. A 2020-01..2025-06 backtest against an October 2024 cutoff is
       58 of 66 months open book.
    2. **What the search cost.** If several variants were screened and the best
       kept, the survivor's t-statistic is the maximum of many draws. The bar
       rises and the sample needed rises quadratically: ten variants take the
       requirement from 48 clean months to 97.

    Args:
        cutoff: The model's knowledge cutoff, ``YYYY-MM``. Use the cutoff of the
            model that produced or evaluated the strategy, not today's date.
        start: Backtest start, ``YYYY-MM``, inclusive.
        end: Backtest end, ``YYYY-MM``, inclusive.
        target_sharpe: The annualised Sharpe **being claimed**, not the one the
            backtest printed. It decides how long the clean remainder must be:
            2.0 needs 12 months, 1.0 needs 48, 0.5 needs 192. Halving it
            quadruples the requirement.
        t_threshold: The t bar the clean sample must clear. 2.0 by default.
        trials: How many strategy variants were screened before this one was
            kept. **If you do not know, do not omit it** — prefer ``trial_grid``
            below, and only fall back to asking the user for a number.
            Omitting it is not a neutral default: it asserts the strategy was
            specified before anyone looked, which is the strongest claim
            available here, and the result will say so. A number given this way
            is recorded as *declared* — unverifiable, and low, because nobody
            counts the variant they glanced at and abandoned.
        trial_grid: The **shape of the search**, as ``{"configs": 6,
            "windows": 4, "scenarios": 2}``. Prefer this over ``trials``
            whenever the search was a sweep, a grid, or any loop you can read
            off the code: the product is the count, and unlike a remembered
            integer it can be recounted by anyone holding the same code. The
            result records it as *derived* and names what a grid cannot see —
            hand-tuned runs, and anything tried before the grid was written.
            Mutually exclusive with ``trials``. If the user reports having run
            a sweep, ask for its dimensions rather than for a total.
        cutoff_source: Where ``cutoff`` came from — the model provider's page for
            the exact snapshot tested. Omit it and the result says the cutoff is
            declared and unsourced; the verdict depends on this input more than
            any other, and moving it earlier always helps. Never fetched here.
            If the provider publishes no cutoff, do not invent one.
        effective_trials: How many of those trials were *independent*. Fifty
            parameter settings of one strategy are not fifty independent tests.
            Pass this only when it has been **measured** —
            ``tools/record_neff.py --table`` computes it from the variants'
            return series (not ``tools/neff.py``: it counts sources, and its
            conventions shrink a screening charge). Do not estimate it,
            and do not let a user assert it without a measurement: a freely
            chosen discount is an escape hatch, not a correction. Omitted, the
            full count is charged, which over-penalises on purpose.
        lang: Language for the prose fields (``note``, ``remedies``,
            ``summary``). ``en`` by default; ``zh`` for Chinese. The numbers
            and ``verdict`` are identical either way. An unrecognised tag falls
            back to English rather than failing — answering in the wrong
            language beats not answering.

    Returns:
        ``verdict`` is the headline and has three values:

        * ``no_holdout`` — nothing is out of sample. Any performance figure from
          this range is recall, not evidence. Do not quote it.
        * ``underpowered`` — some of it is out of sample, but too little to
          support an inference. **Report this as "this backtest cannot tell
          you", not as "the strategy does not work"** — it rejects nothing in
          either direction.
        * ``sufficient`` — length has stopped being the binding constraint.
          This is *not* evidence the strategy works; it means the result has
          become eligible to be examined.

        Also returned: ``open_book_months`` / ``effective_months`` /
        ``months_required`` and ``power_ratio`` (clean months as a fraction of
        what an inference needs); ``selection`` with the corrected t bar and
        what screening cost in months, or ``null`` when ``trials`` was omitted;
        ``note``, carrying the caveats that would otherwise make these numbers
        look better than they are; and ``remedies``, concrete actions ordered by
        what actually caused the failure.

        Surface ``remedies`` to the user rather than inventing advice. They are
        dispatched on the cause — extending the backtest, switching to a model
        with an earlier cutoff, and measuring variant overlap are different
        fixes for different problems, and some do not apply.

    Raises:
        ValueError: on unparseable dates, an inverted range, a trial count that
        cannot be true (fewer than one, or more independent trials than
        trials), or both ``trials`` and ``trial_grid`` at once. These are caller
        errors and are not absorbed into a plausible number.
    """
    if trials is not None and trial_grid:
        raise ValueError(
            "pass trials or trial_grid, not both — two counts of one search "
            "is two answers to one question, and this tool does not pick"
        )
    count = trial_count.from_grid(lang=lang, **trial_grid) if trial_grid else trials
    window = effective_window(
        cutoff, start, end,
        target_sharpe=target_sharpe,
        t_threshold=t_threshold,
        trials=count,
        effective_trials=effective_trials,
        cutoff_source=cutoff_source,
        lang=lang,
    )
    result = window.to_dict()
    result["remedies"] = remedies(window)
    result["summary"] = window.summary()
    return result


@mcp.tool()
def track_record(
    start: str,
    end: str,
    picked: Optional[str] = None,
    target_sharpe: float = 1.0,
    t_threshold: float = 2.0,
    trials: Optional[int] = None,
    effective_trials: Optional[float] = None,
    lang: str = "en",
) -> Dict[str, Any]:
    """Check whether a track record is long enough to mean anything, before copying it.

    Call this **before recommending, ranking or copying** a trader, wallet,
    vault or fund on the strength of its past returns — a copy-trading
    leaderboard, an on-chain whale, a vault's history, a factsheet. No model
    and no knowledge cutoff are involved; use ``knowledge_window`` for
    backtests run with a language model. Pure arithmetic on dates and a count.

    The split is at **the day the record was picked**. Everything up to then
    is the record that got it chosen; only what came after tests the choice.
    So two readings come back, and they are not combined:

    1. ``as_shown`` — the record that got it picked, charged for how many
       records it was picked from. A wallet that tops a board of 4,800 is the
       maximum of 4,800 draws: six months at Sharpe 3 needs 27 months instead
       of 6.
    2. ``since_picked`` — only what happened after ``picked``, at the plain
       bar. Present only when ``picked`` is given.

    Args:
        start: First day or month of the record, ``YYYY-MM`` or ``YYYY-MM-DD``.
        end: Last day or month, inclusive.
        picked: When the record was chosen — when the user started copying,
            or when the board ranked it. **Ask the user rather than omit it**;
            without it there is no out-of-sample reading at all.
        target_sharpe: The annualised Sharpe **being claimed**, not the one
            the record printed.
        t_threshold: The t bar. 2.0 by default.
        trials: How many records this one was chosen from. For a leaderboard,
            every wallet the board ranked — including ones that blew up and
            dropped off — **not 1**. If you do not know, ask the user; omitting
            it is not a neutral default, it asserts this was the only record
            anyone looked at, and the result will say so.
        effective_trials: How many of those were independent. Pass this only
            when it has been **measured** (``tools/record_neff.py`` computes it
            from the wallets' daily returns). Do not estimate it.
        lang: ``en`` or ``zh`` for the prose in ``note``.

    Returns:
        ``as_shown`` and ``since_picked`` (or ``null``), each with ``months``,
        ``months_required``, ``t_bar``, ``verdict`` and ``power_ratio``;
        ``note`` with the caveats. Verdicts:

        * ``underpowered`` — too short to tell. **Report this as "this record
          cannot tell you", not as "the trader has no skill".**
        * ``sufficient`` — length has stopped being the binding constraint. It
          is *not* evidence the user's copy would earn the same: the record is
          the trader's fills, not the user's after latency and slippage.
        * ``no_holdout`` — nothing since the pick yet.

        **Do not quote whichever reading passes.** Report both.

    Raises:
        ValueError: on malformed dates, an inverted range, a pick date outside
        the record, or ``effective_trials`` without ``trials``.
    """
    return _track_record(
        start, end, picked=picked, target_sharpe=target_sharpe,
        t_threshold=t_threshold, trials=trials,
        effective_trials=effective_trials, lang=lang,
    ).to_dict()


@mcp.tool()
def counterfactual_audit(
    perturbations: List[Dict[str, Any]],
    alpha: float = 0.05,
    lang: str = "en",
) -> Dict[str, Any]:
    """Test whether an agent reads its inputs or recites an outcome it already knows.

    Use this when a language model has produced an analysis or a trading
    decision and you need to know whether the *inputs* drove it. It is the third
    axis of this server: ``decision_confidence`` discounts across sources,
    ``knowledge_window`` across time, this one across inputs.

    **You have to run the perturbations yourself before calling this.** The
    procedure is: take the case the agent already analysed, change one fact,
    re-ask, and record whether the conclusion changed. Repeat with different
    changes. This tool scores the resulting table; it cannot generate or
    evaluate the runs for you.

    Two kinds of change are required, with opposite expectations:

    * ``material`` — good news to bad, a policy direction reversed, an earnings
      beat turned into a miss, a covenant broken. The conclusion **should** move.
    * ``cosmetic`` — a renamed ticker, shifted dates, rescaled magnitudes,
      reworded narration. The conclusion **should not** move.

    **Supply both.** With only material changes, "never flips" and "reads
    nothing" are the same observation and the tool will refuse to score it.
    Cosmetic ones are the control that makes the material ones mean something.

    **Six is the minimum**, three of each. A perfect 3+3 split gives p = 0.0500
    exactly; below that no result of any shape can be significant, and the tool
    returns ``no_power`` rather than a flattering verdict. Prefer more.

    Args:
        perturbations: One entry per run, as
            ``{"kind": "material"|"cosmetic", "detail": str, "flipped": bool}``.
            ``flipped`` is your judgement that the agent's conclusion changed —
            not that its wording changed. A different phrasing of the same call
            is **not** a flip. ``detail`` is free text describing what you
            altered; it is echoed back so the report is auditable.
        alpha: Significance bar for the one-sided Fisher test. 0.05 by default.
        lang: ``en`` (default) or ``zh`` for the prose fields.

    Returns:
        ``verdict`` is the headline:

        * ``no_control`` — only one kind supplied. **Not a result.** Report it as
          a missing control and ask the user for the other kind.
        * ``no_power`` — too few perturbations for any outcome to be significant.
          Report as "this audit cannot tell", **never** as a pass or a failure.
        * ``memorised`` — no cosmetic change moved it, and material ones did not
          do significantly better. The agent is reciting, not reading.
        * ``unstable`` — a cosmetic change moved the conclusion at least once.
          Whatever drives this output, it is not the evidence.
        * ``responsive`` — material significantly above cosmetic. **This is not a
          statement that the conclusion is correct**, only that the agent
          responds to changes that matter. Say so when reporting it.

        Also returned: the two flip counts and rates, the exact ``p_value``,
        ``best_possible_p`` (what a perfect split at this size would have
        reached — the number that explains a ``no_power``), ``note`` carrying the
        caveats, and ``remedies``, which are dispatched on what is actually
        missing. Surface the remedies rather than inventing advice.

    **The limit that cannot be engineered away**: whether a conclusion flipped,
    and whether a change was material or cosmetic, are both your labels. Mislabel
    a material change as cosmetic and the audit passes. If you are running the
    perturbations on a user's behalf, show them the list and the labels before
    quoting the verdict.

    Raises:
        ValueError: on an unknown ``kind`` or an ``alpha`` outside (0, 1). These
        are caller errors and are not absorbed into a plausible number.
    """
    parsed = []
    for entry in perturbations:
        if not isinstance(entry, dict):
            raise ValueError("each perturbation must be an object")
        parsed.append(Perturbation(
            kind=str(entry.get("kind", "")),
            detail=str(entry.get("detail", "")),
            flipped=bool(entry.get("flipped", False)),
        ))
    report = perturbation_audit(parsed, alpha=alpha, lang=lang)
    result = report.to_dict()
    result["remedies"] = cf_remedies(report)
    result["summary"] = report.summary()
    result["minimum_perturbations"] = minimum_perturbations(alpha)
    return result


@mcp.tool()
def trace_audit(
    transcript_path: str,
    units: Optional[List[Dict[str, str]]] = None,
    seal: Optional[str] = None,
    holdout: Optional[str] = None,
    gap_result: Optional[str] = None,
    gap_start: Optional[str] = None,
    since: Optional[str] = None,
    until: Optional[str] = None,
    format: Optional[str] = None,
    lang: str = "en",
) -> Dict[str, Any]:
    """Audit an agent's research transcript: how many trials, and was the holdout sealed?

    Call this **before reporting a result from a study an agent ran** — yours
    or another agent's: a backtest sweep, a signal search, a replication. The
    transcript holds what the result does not: every variant tried before this
    one, and whether the held-out data was opened before the plan was fixed.
    Reads the file at ``transcript_path``; writes nothing. Formats: Claude Code
    session JSONL and Codex CLI rollouts are detected; anything else must be
    exported to the generic schema (one ``{"ts", "kind", "tool", "text",
    "call_id"}`` object per line) and passed with ``format="events"``.

    **Patterns are regexes you write for this study and this harness.** Tool
    names and call JSON differ between formats, so read a few events first if
    you are unsure what a call looks like. Decide the units **before** looking
    at any result: choosing the unit after seeing which one gives the smallest
    count is the selection this tool exists to expose.

    Args:
        transcript_path: Path to the transcript file.
        units: Candidate definitions of one trial, each
            ``{"name": ..., "kind": "call" | "output", "pattern": ...}``.
            ``call`` counts distinct matching tool calls; ``output`` counts
            distinct matching lines of tool output. Give several — runs,
            verdicts, statistics — because the point is the spread.
        seal: Regex for the calls that fix the plan (writing a
            preregistration, committing an analysis spec). Pair with
            ``holdout``.
        holdout: Regex for calls that touch the held-out data.
        gap_result: Regex for output lines that report a result. Pair with
            ``gap_start``.
        gap_start: Regex for calls that begin a new analysis.
        since: ISO time; keep events at or after it (UTC if no offset).
        until: ISO time; keep events at or before it.
        format: ``claude_code``, ``codex`` or ``events``; detected if omitted.
        lang: ``en`` or ``zh`` for the prose notes.

    Returns:
        ``units``: one row per unit, each with its own lower-bound trial count
        (provenance ``log``) or ``null`` when nothing matched; ``spread``
        ``[min, max]``. **Report the table and the unit you chose, never a
        single total** — there is none, on purpose. A ``null`` row is a
        pattern that did not match, **not zero trials**.

        ``seal``: ``verdict`` is one of ``unsealed``, ``untouched``,
        ``sealed_first``, ``touched_between`` (plan amended after the holdout
        was first touched) or ``touched_before_seal``. Each touch carries the
        ``output`` it got back. **Do not report ``touched_between`` as a
        violation without reading those outputs**: a touch that only launched
        a background job saw nothing. Equally, ``sealed_first`` is not proof of
        a clean holdout — a script that opens the file without naming it on
        the command line is invisible here; ``blind_to`` says so.

        ``gaps``: raw seconds from each result to the next new analysis, and
        ``human_between`` — whether a person spoke in between (``null`` when
        the format does not record human turns). ``false`` with a short gap is
        the agent changing direction on its own result. Use the flag, not the
        seconds: no threshold is applied, and do not invent one.

    Raises:
        ValueError: on half a pattern pair, nothing to do, a bad regex, a bad
        unit kind or an undetectable format.
    """
    def when(s):
        if not s:
            return None
        from datetime import datetime, timezone
        d = datetime.fromisoformat(s.replace("Z", "+00:00"))
        return d if d.tzinfo else d.replace(tzinfo=timezone.utc)

    unit_objs = [_trace_audit.Unit(u["name"], u["kind"], u["pattern"]) for u in (units or [])]
    # Validate before opening what may be a very large file.
    _trace_audit.audit(_trace_audit.Trace([]), units=unit_objs, seal=seal, holdout=holdout,
                       gap_result=gap_result, gap_start=gap_start, lang=lang)
    with open(transcript_path, encoding="utf-8") as fh:
        trace = _trace_audit.window(_trace_audit.load_trace(fh, format), when(since), when(until))
    return _trace_audit.audit(trace, units=unit_objs, seal=seal, holdout=holdout,
                              gap_result=gap_result, gap_start=gap_start, lang=lang)


@mcp.tool()
def hyperliquid_wallet(address: str, picked_from: Optional[int] = None) -> Dict[str, Any]:
    """Is this Hyperliquid wallet's record skill, or could it be luck?

    Call this **before recommending, ranking or copying** a Hyperliquid
    trader, or when someone cites a wallet's PnL or leaderboard rank as
    evidence. It fetches the wallet's public portfolio history from
    Hyperliquid (no key) and scores the weekly returns, computed from PnL so
    deposits and withdrawals do not count as returns.

    Args:
        address: The wallet, ``0x`` followed by 40 hex characters.
        picked_from: How many wallets this one was chosen from. If it was found
            by sorting a leaderboard, pass the size of the board (Hyperliquid's
            ranks about 47,000 accounts; the current count is ``ranked_from``
            in https://evidencedeflator.com/data/hl/latest.json). **Ask the
            user how they found the wallet rather than omit it**: omitting it
            asserts the wallet was the only one anyone looked at, and the bar
            drops from about 4.9 to 2.

    Returns:
        ``t`` (on the normal scale, adjusted for record length), ``t_student``,
        ``dof``, ``sharpe`` (annualised), ``weeks``, ``verdict``, ``bar``,
        ``months_more_to_clear`` (at the observed Sharpe), ``flags`` and the
        history dates. Verdicts:

        * ``too_short`` — fewer than 8 measurable weeks. Say "this record
          cannot tell you yet", not "no skill".
        * ``luck`` — cannot be told apart from luck at this length.
        * ``clears_single`` — passes the bar for one wallet picked blind, but
          not the leaderboard bar when ``picked_from`` was given.
        * ``clears_board`` — passes the best-of-``picked_from`` bar.
        * ``loses`` — t at or below -2: losing, and not by chance.

        Flags name what t cannot see: ``no_losing_week`` (consistent with
        selling tail risk), ``one_week_majority`` (one week made most of the
        gains), ``pnl_outside_record`` (most PnL was booked while the account
        held under $1,000, so it cannot be turned into a return). **Report the
        flags with the verdict.** A past record is not the user's future
        returns after fees, latency and slippage.

        For a fixed-rule gate, read ``clears_bar`` (t at or above ``bar``,
        which ``bar_rule`` states) instead of the prose; ``source``,
        ``fetched_at`` and the history dates say what data it rests on.
    """
    if not (isinstance(address, str) and address.startswith("0x") and len(address) == 42):
        raise ValueError("address must be 0x followed by 40 hex characters")
    int(address[2:], 16)
    r = hl_wallet.check(address.lower(), picked_from=picked_from)
    r["source"] = SOURCE
    r["fetched_at"] = datetime.now(timezone.utc).strftime("%Y-%m-%dT%H:%M:%SZ")
    r["method_url"] = "https://evidencedeflator.com/method/"
    return r


@mcp.tool()
def list_supported_vendors() -> Dict[str, str]:
    """Vendors with a dedicated adapter, mapped to what each one contributes.

    Call this before ``decision_confidence`` to decide whether to tag a source
    with ``vendor``. Anything not listed still works — it falls back to generic
    shape recognition and the observation says so in its note.
    """
    return supported_vendors()


def main() -> None:
    mcp.run()


if __name__ == "__main__":
    main()
