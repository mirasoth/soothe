"""Verify daemon broadcast events from raw daemon API without TUI logic.

This script connects to the daemon via SDK WebSocket client and verifies:
1. Unified tool call IDs (IG-416 format)
2. Task delegation and step association
3. Tool call and task instance association
4. Stream tool wire events (soothe.stream.tool_call.update)
5. Subagent wire events (soothe.subagent.*)
6. Streaming mode comparison (batch vs streaming)

Usage:
    # Single-mode run (default: streaming)
    python scripts/verify_daemon_events.py [--daemon-url URL] [--timeout SECONDS]

    # Compare all streaming modes (runs the same prompt 2x, one per mode)
    python scripts/verify_daemon_events.py --compare-modes [--timeout SECONDS]

Requirements:
    - Daemon running at the specified URL (default ws://localhost:8765)
    - Valid SootheConfig with providers configured
"""

from __future__ import annotations

import argparse
import asyncio
import json
import logging
import sys
import time
from collections import defaultdict
from dataclasses import dataclass, field
from typing import Any

from soothe_client.websocket import WebSocketClient
from soothe_daemon.query.stream_delivery import StreamDeliveryMode
from soothe_sdk.core.subagent_wire import (
    is_allowlisted_subagent_event_type,
    parse_subagent_wire_agent,
)
from soothe_sdk.ux.stream_tool_wire import (
    STREAM_TOOL_CALL_UPDATE,
    extract_tool_call_updates_from_wire_message,
)
from soothe_sdk.ux.task_namespace import parse_unified_tool_call_id

STREAM_DELIVERY_MODES: list[StreamDeliveryMode] = ["batch", "adaptive", "streaming"]

logging.basicConfig(
    level=logging.INFO,
    format="%(asctime)s [%(levelname)s] %(message)s",
)
logger = logging.getLogger(__name__)


@dataclass
class EventStats:
    """Statistics collected from daemon events."""

    total_events: int = 0
    events_by_type: dict[str, int] = field(default_factory=lambda: defaultdict(int))

    # Tool call tracking
    tool_call_ids: set[str] = field(default_factory=set)
    unified_tool_call_ids: set[str] = field(default_factory=set)
    legacy_tool_call_ids: set[str] = field(default_factory=set)

    # Step association
    tool_calls_by_step: dict[str, set[str]] = field(default_factory=lambda: defaultdict(set))

    # Step description tracking (step_id -> description)
    step_descriptions: dict[str, str] = field(default_factory=dict)
    step_started_events: list[dict[str, Any]] = field(
        default_factory=list
    )  # Raw events for analysis
    plan_decision_events: list[dict[str, Any]] = field(default_factory=list)  # Plan decision events

    # Task delegation tracking
    task_tool_calls: set[str] = field(default_factory=set)
    task_scopes: dict[str, tuple[str, str, str]] = field(
        default_factory=dict
    )  # tool_call_id -> (id, subagent_type, step_id)

    # Subagent events
    subagent_events_by_type: dict[str, int] = field(default_factory=lambda: defaultdict(int))
    subagent_events_by_agent: dict[str, int] = field(default_factory=lambda: defaultdict(int))

    # Stream tool wire events
    stream_tool_updates: list[dict[str, Any]] = field(default_factory=list)

    # Args accumulation tracking (like TUI's pending_tool_calls)
    pending_tool_calls: dict[str, dict[str, Any]] = field(default_factory=dict)
    # tool_call_id -> {"name": str, "args_str": str, "is_complete_json": bool}

    # Track last active tool_call_id for orphan chunk attachment
    last_active_tool_call_id: str = ""

    # Final accumulated args per tool_call_id
    accumulated_args: dict[str, dict[str, Any]] = field(default_factory=dict)

    # Validation errors
    errors: list[str] = field(default_factory=list)

    # Streaming mode specific metrics
    goal_completion_chunks: int = 0  # messages-mode chunks with phase=goal_completion
    goal_completion_text_chars: int = 0  # total chars across all goal_completion chunks
    goal_completion_flush_events: int = (
        0  # number of emitted goal_completion messages (after coalescing)
    )
    messages_mode_events: int = 0  # total messages-mode events received
    custom_mode_events: int = 0  # total custom-mode events received
    event_timestamps: list[float] = field(default_factory=list)  # timestamps for latency analysis


def classify_tool_call_id(tool_call_id: str) -> tuple[str, str, int | None, str]:
    """Parse and classify a tool_call_id.

    Returns:
        (step_id, type_code, task_idx, tool_info)
        - step_id: empty for legacy, non-empty for unified
        - type_code: 's' for step-level, 't' for task-level, '' for legacy
        - task_idx: None for step-level, int for task-level
        - tool_info: tool name and index fragment
    """
    return parse_unified_tool_call_id(tool_call_id)


def validate_event(event: dict[str, Any], stats: EventStats) -> None:
    """Validate a single daemon event and update statistics."""

    stats.total_events += 1
    event_type = event.get("type", "unknown")
    stats.events_by_type[event_type] += 1
    stats.event_timestamps.append(time.monotonic())

    # Handle wrapped events (daemon wraps LangGraph stream events in "event" type)
    if event_type == "event":
        # The daemon wraps events with: {"type": "event", "namespace": [...], "mode": "...", "data": ...}
        mode = event.get("mode", "")
        data = event.get("data")
        namespace = event.get("namespace", [])

        # Log all wrapped events for debugging
        logger.debug(
            "Wrapped event: mode=%s namespace=%s data_type=%s",
            mode,
            namespace,
            type(data).__name__,
        )

        # Handle messages stream events - data is a tuple (message, metadata)
        if mode == "messages":
            stats.messages_mode_events += 1
            if isinstance(data, (list, tuple)) and len(data) >= 1:
                msg = data[0]
                if isinstance(msg, dict):
                    # Track goal_completion chunks
                    phase = msg.get("phase", "")
                    if phase == "goal_completion":
                        stats.goal_completion_chunks += 1
                        stats.goal_completion_flush_events += 1
                        content = msg.get("content", "")
                        if isinstance(content, str):
                            stats.goal_completion_text_chars += len(content)
                        elif isinstance(content, list):
                            for part in content:
                                if isinstance(part, dict) and isinstance(part.get("text"), str):
                                    stats.goal_completion_text_chars += len(part["text"])

                    # Log the message structure with full tool_calls content
                    tool_calls = msg.get("tool_calls", [])
                    chunks = msg.get("tool_call_chunks", [])
                    msg_type = msg.get("type", "unknown")

                    # Distinguish AIMessage vs AIMessageChunk
                    logger.info(
                        "Messages event: type=%s tool_calls=%d chunks=%d",
                        msg_type,
                        len(tool_calls),
                        len(chunks),
                    )

                    # --- Args accumulation (like TUI's accumulate_tool_call_chunks) ---
                    for tcc in chunks:
                        if not isinstance(tcc, dict):
                            continue
                        tc_id_raw = tcc.get("id")
                        tc_id = str(tc_id_raw) if tc_id_raw not in (None, "") else ""
                        tc_name = tcc.get("name")
                        tc_args = tcc.get("args", "")

                        # First chunk with a tool name: register the pending tool call
                        if tc_name and tc_id and tc_id not in stats.pending_tool_calls:
                            if isinstance(tc_args, str):
                                args_str = tc_args
                                is_complete = False  # String may be partial JSON
                            elif isinstance(tc_args, dict) and tc_args:
                                args_str = json.dumps(tc_args)
                                is_complete = True  # Dict yields complete JSON
                            else:
                                args_str = ""
                                is_complete = False  # Empty or missing args
                            stats.pending_tool_calls[tc_id] = {
                                "name": tc_name,
                                "args_str": args_str,
                                "is_complete_json": is_complete,
                            }
                            stats.last_active_tool_call_id = tc_id
                            logger.debug(
                                "Registered pending tool: id=%s name=%s args_str='%s'",
                                tc_id,
                                tc_name,
                                args_str[:50],
                            )
                        # Some providers send final args as a dict on a later chunk
                        elif (
                            tc_id
                            and tc_id in stats.pending_tool_calls
                            and isinstance(tc_args, dict)
                            and tc_args
                        ):
                            stats.pending_tool_calls[tc_id]["args_str"] = json.dumps(tc_args)
                            stats.pending_tool_calls[tc_id]["is_complete_json"] = True
                            logger.debug(
                                "Updated pending tool with dict args: id=%s args=%s",
                                tc_id,
                                str(tc_args)[:50],
                            )
                        # Subsequent chunks: accumulate partial JSON strings
                        elif (
                            tc_id
                            and tc_id in stats.pending_tool_calls
                            and isinstance(tc_args, str)
                            and tc_args
                        ):
                            if stats.pending_tool_calls[tc_id].get("is_complete_json"):
                                # Provider refined args → restart accumulation
                                stats.pending_tool_calls[tc_id]["args_str"] = tc_args
                                stats.pending_tool_calls[tc_id]["is_complete_json"] = False
                            else:
                                # Normal partial accumulation
                                stats.pending_tool_calls[tc_id]["args_str"] += tc_args
                                logger.debug(
                                    "Accumulated chunk: id=%s args_str='%s'",
                                    tc_id,
                                    stats.pending_tool_calls[tc_id]["args_str"][:50],
                                )
                        # Chunks without id: attach to last active tool (the one being streamed currently)
                        elif tc_args and isinstance(tc_args, str) and tc_args:
                            last_id = stats.last_active_tool_call_id
                            if last_id and last_id in stats.pending_tool_calls:
                                if not stats.pending_tool_calls[last_id].get("_emitted"):
                                    stats.pending_tool_calls[last_id]["args_str"] += tc_args
                                    logger.debug(
                                        "Attached orphan chunk to last active: id=%s args_str='%s'",
                                        last_id,
                                        stats.pending_tool_calls[last_id]["args_str"][:50],
                                    )

                    # Also check tool_calls for complete args (terminal message)
                    for tc in tool_calls:
                        if not isinstance(tc, dict):
                            continue
                        tc_id = str(tc.get("id") or "").strip()
                        if not tc_id:
                            continue
                        tc_args = tc.get("args")
                        if isinstance(tc_args, dict) and tc_args:
                            # This is a terminal message with complete args
                            if tc_id in stats.pending_tool_calls:
                                stats.pending_tool_calls[tc_id]["args_str"] = json.dumps(tc_args)
                                stats.pending_tool_calls[tc_id]["is_complete_json"] = True
                                stats.pending_tool_calls[tc_id]["_from_terminal"] = True
                                logger.info(
                                    "Terminal tool_call with args: id=%s args=%s",
                                    tc_id,
                                    str(tc_args)[:100],
                                )

                    # Extract tool_call_ids from message (using standard function)
                    updates = extract_tool_call_updates_from_wire_message(msg)
                    logger.debug("Extracted %d tool call updates from message", len(updates))

                    # Also manually capture tool_call_ids even with empty args
                    # (the extract function skips entries with empty args)
                    manual_ids: set[str] = set()
                    for tc in tool_calls:
                        if isinstance(tc, dict):
                            tid = str(tc.get("id") or "").strip()
                            if tid and tid not in manual_ids:
                                manual_ids.add(tid)

                    for ch in chunks:
                        if isinstance(ch, dict):
                            tid = str(ch.get("id") or "").strip()
                            if tid and tid not in manual_ids:
                                manual_ids.add(tid)

                    # Record all found tool_call_ids
                    for tid in manual_ids:
                        stats.tool_call_ids.add(tid)
                        step_id, type_code, task_idx, tool_info = classify_tool_call_id(tid)

                        logger.info(
                            "Tool call ID found: id=%s step=%s type_code=%s tool=%s",
                            tid,
                            step_id,
                            type_code,
                            tool_info,
                        )

                        if step_id and type_code in ("s", "t"):
                            stats.unified_tool_call_ids.add(tid)
                            stats.tool_calls_by_step[step_id].add(tid)
                        else:
                            stats.legacy_tool_call_ids.add(tid)

                    for update in updates:
                        stats.stream_tool_updates.append(update)
                        tid = update.get("tool_call_id", "")
                        if tid:
                            stats.tool_call_ids.add(tid)
                            step_id, type_code, task_idx, tool_info = classify_tool_call_id(tid)

                            if step_id and type_code in ("s", "t"):
                                stats.unified_tool_call_ids.add(tid)
                                stats.tool_calls_by_step[step_id].add(tid)
                            else:
                                stats.legacy_tool_call_ids.add(tid)

        # Handle custom mode events (stream tool wire events, subagent events)
        elif mode == "custom":
            stats.custom_mode_events += 1
            if isinstance(data, dict):
                inner_type = data.get("type", "")

                # Also log full data for non-status events
                if inner_type and inner_type not in ("status", "daemon_status"):
                    logger.info(
                        "Custom event payload: type=%s payload=%s",
                        inner_type,
                        json.dumps(data, separators=(",", ":"))[:300],
                    )

                if inner_type == STREAM_TOOL_CALL_UPDATE:
                    stats.stream_tool_updates.append(data)
                    tool_call_id = data.get("tool_call_id", "")
                    name = data.get("name", "")
                    args = data.get("args", {})

                    if tool_call_id:
                        stats.tool_call_ids.add(tool_call_id)
                        step_id, type_code, task_idx, tool_info = classify_tool_call_id(
                            tool_call_id
                        )

                        if step_id:
                            stats.unified_tool_call_ids.add(tool_call_id)
                            stats.tool_calls_by_step[step_id].add(tool_call_id)

                            if type_code == "t":
                                logger.debug(
                                    "Task-level tool: id=%s step=%s task_idx=%s tool=%s",
                                    tool_call_id,
                                    step_id,
                                    task_idx,
                                    tool_info,
                                )
                            elif type_code == "s":
                                logger.debug(
                                    "Step-level tool: id=%s step=%s tool=%s",
                                    tool_call_id,
                                    step_id,
                                    tool_info,
                                )
                                if name == "task":
                                    stats.task_tool_calls.add(tool_call_id)
                                    subagent_type = args.get("subagent_type", "?")
                                    stats.task_scopes[tool_call_id] = (
                                        tool_call_id,
                                        subagent_type,
                                        step_id,
                                    )
                        else:
                            stats.legacy_tool_call_ids.add(tool_call_id)
                            stats.errors.append(
                                f"Legacy tool_call_id without unified format: {tool_call_id}"
                            )

                elif is_allowlisted_subagent_event_type(inner_type):
                    stats.subagent_events_by_type[inner_type] += 1
                    agent = parse_subagent_wire_agent(inner_type)
                    if agent:
                        stats.subagent_events_by_agent[agent] += 1

                    step_id = data.get("step_id", "")
                    if step_id:
                        logger.debug(
                            "Subagent event: type=%s agent=%s step=%s",
                            inner_type,
                            agent,
                            step_id,
                        )

                elif inner_type == "soothe.cognition.strange_loop.plan.decision":
                    stats.plan_decision_events.append(data)
                    steps = data.get("steps", [])
                    for step in steps:
                        step_id = step.get("id", "")
                        description = step.get("description", "")
                        if step_id:
                            logger.info(
                                "Plan decision: step_id=%s description='%s'",
                                step_id,
                                description[:80],
                            )

                elif inner_type == "soothe.cognition.strange_loop.step.started":
                    stats.step_started_events.append(data)
                    step_id = data.get("step_id", "")
                    description = data.get("description", "")
                    if step_id:
                        # Track step descriptions
                        stats.step_descriptions[step_id] = description
                        logger.info(
                            "Step started: step_id=%s description='%s'",
                            step_id,
                            description[:80],
                        )

                elif inner_type == "soothe.cognition.strange_loop.step.completed":
                    step_id = data.get("step_id", "")
                    if step_id:
                        logger.info(
                            "Step completed: step_id=%s success=%s",
                            step_id,
                            data.get("success", "?"),
                        )

                elif inner_type:
                    logger.debug("Custom inner event type: %s", inner_type)

        return

    # Check for stream tool call update events (unwrapped)
    if event_type == STREAM_TOOL_CALL_UPDATE:
        stats.stream_tool_updates.append(event)
        tool_call_id = event.get("tool_call_id", "")
        name = event.get("name", "")
        args = event.get("args", {})

        if tool_call_id:
            stats.tool_call_ids.add(tool_call_id)
            step_id, type_code, task_idx, tool_info = classify_tool_call_id(tool_call_id)

            if step_id:
                stats.unified_tool_call_ids.add(tool_call_id)
                stats.tool_calls_by_step[step_id].add(tool_call_id)

                if type_code == "t":
                    logger.debug(
                        "Task-level tool: id=%s step=%s task_idx=%s tool=%s",
                        tool_call_id,
                        step_id,
                        task_idx,
                        tool_info,
                    )
                elif type_code == "s":
                    logger.debug(
                        "Step-level tool: id=%s step=%s tool=%s",
                        tool_call_id,
                        step_id,
                        tool_info,
                    )
                    if name == "task":
                        stats.task_tool_calls.add(tool_call_id)
                        subagent_type = args.get("subagent_type", "?")
                        stats.task_scopes[tool_call_id] = (
                            tool_call_id,
                            subagent_type,
                            step_id,
                        )
            else:
                stats.legacy_tool_call_ids.add(tool_call_id)
                stats.errors.append(f"Legacy tool_call_id without unified format: {tool_call_id}")

    # Check for subagent wire events (unwrapped)
    elif is_allowlisted_subagent_event_type(event_type):
        stats.subagent_events_by_type[event_type] += 1
        agent = parse_subagent_wire_agent(event_type)
        if agent:
            stats.subagent_events_by_agent[agent] += 1

        step_id = event.get("step_id", "")
        if step_id:
            logger.debug("Subagent event: type=%s agent=%s step=%s", event_type, agent, step_id)

    # Check for messages stream events (unwrapped)
    elif event_type == "stream" or event.get("mode") == "messages":
        data = event.get("data")
        if isinstance(data, (list, tuple)) and len(data) >= 1:
            msg = data[0]
            if isinstance(msg, dict):
                updates = extract_tool_call_updates_from_wire_message(msg)
                for update in updates:
                    stats.stream_tool_updates.append(update)
                    tid = update.get("tool_call_id", "")
                    if tid:
                        stats.tool_call_ids.add(tid)
                        step_id, type_code, task_idx, tool_info = classify_tool_call_id(tid)

                        if step_id:
                            stats.unified_tool_call_ids.add(tid)
                            stats.tool_calls_by_step[step_id].add(tid)
                        else:
                            stats.legacy_tool_call_ids.add(tid)


def print_summary(stats: EventStats) -> None:
    """Print verification summary."""

    print("\n" + "=" * 80)
    print("DAEMON EVENT VERIFICATION SUMMARY")
    print("=" * 80)

    print(f"\nTotal events received: {stats.total_events}")

    print("\n--- Events by Type ---")
    for event_type, count in sorted(stats.events_by_type.items(), key=lambda x: -x[1]):
        print(f"  {event_type}: {count}")

    print("\n--- Tool Call ID Classification ---")
    print(f"  Total tool_call_ids: {len(stats.tool_call_ids)}")
    print(f"  Unified format (IG-416): {len(stats.unified_tool_call_ids)}")
    print(f"  Legacy format: {len(stats.legacy_tool_call_ids)}")

    if stats.legacy_tool_call_ids:
        print("\n  Legacy IDs (need unified format):")
        for tid in sorted(stats.legacy_tool_call_ids)[:10]:
            print(f"    - {tid}")
        if len(stats.legacy_tool_call_ids) > 10:
            print(f"    ... and {len(stats.legacy_tool_call_ids) - 10} more")

    print("\n--- Tool Calls by Step ---")
    for step_id, tids in sorted(stats.tool_calls_by_step.items()):
        description = stats.step_descriptions.get(step_id, "(no description)")
        print(f"  Step {step_id}: {len(tids)} tool calls")
        print(
            f"    description: '{description[:60]}...'"
            if len(description) > 60
            else f"    description: '{description}'"
        )
        for tid in sorted(tids)[:5]:
            _, type_code, task_idx, tool_info = classify_tool_call_id(tid)
            type_label = "step" if type_code == "s" else f"task[{task_idx}]"
            print(f"    - {tid} ({type_label}: {tool_info})")

    # --- Step Description Analysis ---
    print("\n--- Step Description Analysis ---")
    print(f"  Plan decision events: {len(stats.plan_decision_events)}")
    print(f"  Step started events: {len(stats.step_started_events)}")
    print(f"  Unique step_ids tracked: {len(stats.step_descriptions)}")

    # Check for duplicate descriptions (potential issue)
    desc_to_steps: dict[str, list[str]] = defaultdict(list)
    for step_id, desc in stats.step_descriptions.items():
        desc_to_steps[desc].append(step_id)

    duplicates = {desc: steps for desc, steps in desc_to_steps.items() if len(steps) > 1}
    if duplicates:
        print("\n  ⚠ DUPLICATE DESCRIPTIONS DETECTED (multiple steps share same description):")
        for desc, steps in sorted(duplicates.items(), key=lambda x: -len(x[1])):
            print(f"    Description: '{desc[:50]}...'")
            print(f"    Used by steps: {', '.join(steps)}")
        stats.errors.append("Multiple steps share identical descriptions")

    # Show all plan decision steps
    if stats.plan_decision_events:
        print("\n  Plan decisions breakdown:")
        for i, plan in enumerate(stats.plan_decision_events[:3]):
            steps = plan.get("steps", [])
            execution_mode = plan.get("execution_mode", "unknown")
            iteration = plan.get("iteration", -1)
            print(f"    Plan #{i + 1} (iteration={iteration}, mode={execution_mode}):")
            for step in steps[:5]:
                step_id = step.get("id", "?")
                desc = step.get("description", "")
                print(
                    f"      - {step_id}: '{desc[:50]}...'"
                    if len(desc) > 50
                    else f"      - {step_id}: '{desc}'"
                )

    print("\n--- Task Delegation ---")
    print(f"  Task tool calls: {len(stats.task_tool_calls)}")
    for tid in sorted(stats.task_tool_calls):
        scope = stats.task_scopes.get(tid)
        if scope:
            _, subagent_type, step_id = scope
            print(f"    - {tid}: subagent={subagent_type} step={step_id}")

    print("\n--- Stream Tool Wire Events ---")
    print(f"  Total: {len(stats.stream_tool_updates)}")
    # Group by tool name
    by_name = defaultdict(list)
    for update in stats.stream_tool_updates:
        by_name[update.get("name", "unknown")].append(update)
    for name, updates in sorted(by_name.items(), key=lambda x: -len(x[1])):
        print(f"  {name}: {len(updates)} updates")

    # --- Args Accumulation Summary ---
    print("\n--- Args Accumulation (Streaming Chunk Merge) ---")
    if stats.pending_tool_calls:
        print(f"  Pending tool calls tracked: {len(stats.pending_tool_calls)}")
        for tc_id, state in sorted(stats.pending_tool_calls.items()):
            args_str = state.get("args_str", "")
            is_complete = state.get("is_complete_json", False)
            name = state.get("name", "unknown")
            from_terminal = state.get("_from_terminal", False)

            # Try to parse accumulated args
            parsed_args = {}
            parse_error = None
            if args_str:
                try:
                    parsed = json.loads(args_str)
                    if isinstance(parsed, dict):
                        parsed_args = parsed
                except json.JSONDecodeError as e:
                    parse_error = str(e)[:50]

            status = (
                "✓ complete" if is_complete else ("✓ terminal" if from_terminal else "⏳ partial")
            )
            if parse_error:
                status = f"⚠ parse error: {parse_error}"

            args_preview = str(parsed_args)[:80] if parsed_args else args_str[:80]
            print(f"  {tc_id}:")
            print(f"    name: {name}")
            print(f"    status: {status}")
            print(f"    args: {args_preview if args_preview else '(empty)'}")
    else:
        print("  No tool calls tracked for args accumulation")

    print("\n--- Subagent Wire Events ---")
    print(f"  Total: {sum(stats.subagent_events_by_type.values())}")
    for agent, count in sorted(stats.subagent_events_by_agent.items()):
        print(f"  Agent '{agent}': {count} events")
    for event_type, count in sorted(stats.subagent_events_by_type.items()):
        print(f"    {event_type}: {count}")

    print("\n--- Validation Errors ---")
    if stats.errors:
        print(f"  {len(stats.errors)} errors found:")
        for err in stats.errors[:20]:
            print(f"    - {err}")
        if len(stats.errors) > 20:
            print(f"    ... and {len(stats.errors) - 20} more")
    else:
        print("  No validation errors")

    # Streaming mode metrics
    print("\n--- Streaming Mode Metrics ---")
    print(f"  messages-mode events:  {stats.messages_mode_events}")
    print(f"  custom-mode events:    {stats.custom_mode_events}")
    print(f"  goal_completion chunks received: {stats.goal_completion_chunks}")
    print(f"  goal_completion flush events:   {stats.goal_completion_flush_events}")
    print(f"  goal_completion text chars:     {stats.goal_completion_text_chars}")
    if stats.goal_completion_chunks > 0:
        ratio = (
            stats.goal_completion_text_chars / stats.goal_completion_flush_events
            if stats.goal_completion_flush_events
            else 0
        )
        print(f"  avg chars per flush:            {ratio:.1f}")
    if len(stats.event_timestamps) >= 2:
        duration = stats.event_timestamps[-1] - stats.event_timestamps[0]
        print(f"  event stream duration:          {duration:.2f}s")
        print(
            f"  events/sec:                     {stats.total_events / duration:.1f}"
            if duration > 0
            else "  events/sec: N/A"
        )

    print("\n" + "=" * 80)

    # Return pass/fail status
    has_unified = len(stats.unified_tool_call_ids) > 0
    has_errors = len(stats.errors) > 0
    has_legacy = len(stats.legacy_tool_call_ids) > 0

    if has_unified and not has_errors:
        print("VERIFICATION PASSED: Unified tool call IDs are correctly formatted")
        return True
    elif has_errors:
        print("VERIFICATION FAILED: Validation errors detected")
        return False
    elif has_legacy and not has_unified:
        print(
            "VERIFICATION INCOMPLETE: Only legacy tool_call_ids found (daemon may not be using IG-416)"
        )
        return None
    else:
        print("VERIFICATION INCOMPLETE: No tool_call_ids found in events")
        return None


async def run_verification(
    daemon_url: str,
    test_prompt: str,
    timeout: float,
    stream_delivery: StreamDeliveryMode = "adaptive",
) -> EventStats:
    """Run verification by connecting to daemon and collecting events."""

    stats = EventStats()
    client = WebSocketClient(daemon_url, client_id="verify_events")

    logger.info("Connecting to daemon at %s", daemon_url)

    try:
        await client.connect()
        logger.info("Connected to daemon")

        # Wait for daemon ready
        try:
            ready_event = await client.fetch_daemon_status(timeout=5.0)
            logger.info("Daemon ready: state=%s", ready_event.get("state"))
        except RuntimeError as e:
            logger.warning("Daemon readiness check failed: %s", e)
        except TimeoutError:
            logger.warning("Daemon readiness timeout (continuing anyway)")

        # Create a new loop (blocking RPC returns the result directly)
        result = await client.request("loop_new", {}, timeout=timeout)
        loop_id = result.get("loop_id")
        if loop_id:
            logger.info("Created loop: %s", loop_id)
        else:
            logger.error("No loop_id received from daemon")
            return stats

        # Subscribe to the loop's event stream
        await client.subscribe(
            "loop_events",
            {"loop_id": loop_id, "stream_delivery": stream_delivery},
            timeout=timeout,
        )
        logger.info("Subscribed to loop: %s", loop_id)

        # Send test input
        logger.info("Sending test prompt: %s", test_prompt[:100])
        await client.send_input(loop_id=loop_id, text=test_prompt)

        # Collect events until timeout or completion
        logger.info("Collecting events for %s seconds...", timeout)
        start_time = time.monotonic()

        while time.monotonic() - start_time < timeout:
            event = await client.read_event()
            if event is None:
                # Connection closed
                logger.info("Connection closed by daemon")
                break

            validate_event(event, stats)

            # Check for agent loop completion (wrapped in custom event envelope)
            if event.get("type") == "event" and event.get("mode") == "custom":
                data = event.get("data")
                if isinstance(data, dict):
                    inner_type = data.get("type", "")
                    if inner_type == "soothe.cognition.strange_loop.completed":
                        logger.info("Agent loop completed: %s", data.get("status"))
                        break

        logger.info("Event collection complete")

    except ConnectionError as e:
        logger.error("Connection error: %s", e)
        stats.errors.append(f"Connection error: {e}")
    except TimeoutError as e:
        logger.error("Timeout: %s", e)
        stats.errors.append(f"Timeout: {e}")
    except Exception as e:
        logger.exception("Unexpected error")
        stats.errors.append(f"Unexpected error: {e}")
    finally:
        await client.close()
        logger.info("Disconnected from daemon")

    return stats


def print_mode_comparison(all_stats: dict[StreamDeliveryMode, EventStats]) -> None:
    """Print a side-by-side comparison of streaming modes."""

    print("\n" + "=" * 80)
    print("STREAMING MODE COMPARISON: batch vs streaming")
    print("=" * 80)

    # Header row
    metrics = [
        ("Total events", lambda s: s.total_events),
        ("messages-mode events", lambda s: s.messages_mode_events),
        ("custom-mode events", lambda s: s.custom_mode_events),
        ("goal_completion chunks", lambda s: s.goal_completion_chunks),
        ("goal_completion flush events", lambda s: s.goal_completion_flush_events),
        ("goal_completion text chars", lambda s: s.goal_completion_text_chars),
        (
            "avg chars/flush",
            lambda s: (
                f"{s.goal_completion_text_chars / s.goal_completion_flush_events:.1f}"
                if s.goal_completion_flush_events
                else "N/A"
            ),
        ),
        ("Tool call IDs", lambda s: len(s.tool_call_ids)),
        ("Unified tool call IDs", lambda s: len(s.unified_tool_call_ids)),
        ("Stream tool updates", lambda s: len(s.stream_tool_updates)),
        ("Subagent events", lambda s: sum(s.subagent_events_by_type.values())),
        (
            "Event stream duration (s)",
            lambda s: (
                f"{s.event_timestamps[-1] - s.event_timestamps[0]:.2f}"
                if len(s.event_timestamps) >= 2
                else "N/A"
            ),
        ),
        (
            "Events/sec",
            lambda s: (
                f"{s.total_events / (s.event_timestamps[-1] - s.event_timestamps[0]):.1f}"
                if len(s.event_timestamps) >= 2
                and (s.event_timestamps[-1] - s.event_timestamps[0]) > 0
                else "N/A"
            ),
        ),
        ("Validation errors", lambda s: len(s.errors)),
    ]

    # Column widths
    mode_col_w = (
        max(len(str(all_stats[m].total_events)) for m in STREAM_DELIVERY_MODES if m in all_stats)
        + 2
    )
    mode_col_w = max(mode_col_w, 8)

    # Print header
    header = f"  {'Metric':<30s}"
    for mode in STREAM_DELIVERY_MODES:
        if mode in all_stats:
            header += f" {mode:>{mode_col_w}s}"
    print(header)
    print(
        f"  {'-' * 30}"
        + ("-" * (mode_col_w + 1)) * sum(1 for m in STREAM_DELIVERY_MODES if m in all_stats)
    )

    # Print rows
    for label, getter in metrics:
        row = f"  {label:<30s}"
        for mode in STREAM_DELIVERY_MODES:
            if mode in all_stats:
                val = getter(all_stats[mode])
                row += f" {str(val):>{mode_col_w}s}"
        print(row)

    # Coalescing ratio analysis
    print("\n--- Coalescing Ratio Analysis ---")
    for mode in STREAM_DELIVERY_MODES:
        if mode not in all_stats:
            continue
        s = all_stats[mode]
        if s.goal_completion_chunks > 0 and s.goal_completion_flush_events > 0:
            ratio = s.goal_completion_chunks / s.goal_completion_flush_events
            print(
                f"  {mode:>8s}: {s.goal_completion_chunks} raw chunks → {s.goal_completion_flush_events} flush events (coalesce ratio: {ratio:.1f}x)"
            )
        else:
            print(f"  {mode:>8s}: no goal_completion events")

    # Explain behavioral expectations
    print("\n--- Expected Behavior ---")
    print("  batch:     goal_completion text suppressed until loop completes → 1 flush event")
    print(
        "  streaming: every goal_completion chunk emitted individually → flush count ≈ chunk count"
    )

    # Validate expectations
    print("\n--- Validation ---")
    all_pass = True
    for mode in STREAM_DELIVERY_MODES:
        if mode not in all_stats:
            continue
        s = all_stats[mode]
        gc = s.goal_completion_chunks
        fl = s.goal_completion_flush_events

        if gc == 0:
            print(f"  {mode:>8s}: SKIP (no goal_completion events)")
            continue

        if mode == "batch":
            if fl <= 1:
                print(
                    f"  {mode:>8s}: PASS (batch mode produced {fl} flush event(s) for {gc} chunks)"
                )
            else:
                print(f"  {mode:>8s}: WARN (batch mode produced {fl} flush events, expected ≤1)")
                all_pass = False
        elif mode == "streaming":
            if fl == gc:
                print(f"  {mode:>8s}: PASS (streaming mode: 1:1 chunk-to-flush, {gc} each)")
            else:
                print(
                    f"  {mode:>8s}: WARN (streaming mode: {gc} chunks → {fl} flush events, expected equal)"
                )
                all_pass = False

    if all_pass:
        print("\n  ALL MODE VALIDATIONS PASSED")
    else:
        print("\n  SOME MODE VALIDATIONS HAD WARNINGS")

    print("\n" + "=" * 80)


async def run_mode_comparison(
    daemon_url: str,
    test_prompt: str,
    timeout: float,
) -> dict[StreamDeliveryMode, EventStats]:
    """Run verification for all streaming modes and return per-mode stats."""

    all_stats: dict[StreamDeliveryMode, EventStats] = {}

    for i, mode in enumerate(STREAM_DELIVERY_MODES):
        print(f"\n{'=' * 40}")
        print(f"  Running mode {i + 1}/2: {mode}")
        print(f"{'=' * 40}")

        logger.info("Starting verification with stream_delivery=%s", mode)
        stats = await run_verification(
            daemon_url=daemon_url,
            test_prompt=test_prompt,
            timeout=timeout,
            stream_delivery=mode,
        )
        all_stats[mode] = stats

        # Brief pause between runs to let daemon settle
        if i < len(STREAM_DELIVERY_MODES) - 1:
            logger.info("Waiting 3s before next mode run...")
            await asyncio.sleep(3)

    return all_stats


def main() -> int:
    """Main entry point."""

    parser = argparse.ArgumentParser(description="Verify daemon broadcast events without TUI logic")
    parser.add_argument(
        "--daemon-url",
        default="ws://localhost:8765",
        help="Daemon WebSocket URL (default: ws://localhost:8765)",
    )
    parser.add_argument(
        "--prompt",
        default="List the files in the current directory and read the README if it exists",
        help="Test prompt to send to daemon",
    )
    parser.add_argument(
        "--timeout",
        type=float,
        default=60.0,
        help="Timeout in seconds for event collection (default: 60)",
    )
    parser.add_argument(
        "--stream-delivery",
        choices=["batch", "streaming"],
        default="streaming",
        help="Stream delivery mode (default: streaming)",
    )
    parser.add_argument(
        "--compare-modes",
        action="store_true",
        help="Run all streaming modes and compare results side-by-side",
    )
    parser.add_argument(
        "--verbose",
        action="store_true",
        help="Enable verbose logging",
    )

    args = parser.parse_args()

    if args.verbose:
        logging.getLogger().setLevel(logging.DEBUG)

    logger.info("Starting daemon event verification")
    logger.info("Daemon URL: %s", args.daemon_url)
    logger.info("Test prompt: %s", args.prompt[:100])
    logger.info("Timeout: %s seconds", args.timeout)

    if args.compare_modes:
        all_stats = asyncio.run(
            run_mode_comparison(
                daemon_url=args.daemon_url,
                test_prompt=args.prompt,
                timeout=args.timeout,
            )
        )

        # Print individual summaries
        for mode in STREAM_DELIVERY_MODES:
            if mode in all_stats:
                print(f"\n{'#' * 80}")
                print(f"# INDIVIDUAL SUMMARY: {mode} mode")
                print(f"{'#' * 80}")
                print_summary(all_stats[mode])

        # Print comparison
        print_mode_comparison(all_stats)
        return 0
    else:
        logger.info("Stream delivery mode: %s", args.stream_delivery)
        stats = asyncio.run(
            run_verification(
                daemon_url=args.daemon_url,
                test_prompt=args.prompt,
                timeout=args.timeout,
                stream_delivery=args.stream_delivery,
            )
        )

        result = print_summary(stats)

        if result is True:
            return 0
        elif result is False:
            return 1
        else:
            return 2  # Incomplete


if __name__ == "__main__":
    sys.exit(main())
