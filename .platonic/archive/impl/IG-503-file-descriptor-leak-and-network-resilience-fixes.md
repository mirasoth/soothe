# IG-503: File Descriptor Leak and Network Resilience Fixes

> Status: **Implemented**
> Created: 2025-06-25
> Scope: Fix file descriptor exhaustion causing cascading failures; add connection error resilience to planner LLM calls

## Summary

This implementation addresses two critical issues identified in loop `2b67` log analysis:

1. **File Descriptor Exhaustion (errno 24)** - Fixed by adding pre-flight checks and explicit subprocess cleanup in `grep_search.py`
2. **LLM Connection Errors** - Fixed by adding retry with exponential backoff in `planner.py` and `llm_rate_limit.py`

All changes are backward compatible and require no configuration updates.

## Files Modified

- `packages/soothe/src/soothe/core/filesystem/grep_search.py` - FD limit handling
- `packages/soothe/src/soothe/sloop/planning/planner.py` - Network retry for planner LLM calls
- `packages/soothe/src/soothe/middleware/llm_rate_limit.py` - Connection error retry in middleware

## Problem Statement

### Issue 1: File Descriptor Exhaustion (`[Errno 24] Too many open files`)

**Symptoms from loop 2b67 log analysis:**
- `ag grep failed ([Errno 24] Too many open files)` - 5 occurrences
- `ThreadLogger flush failed` - OSError on conversation.jsonl
- `Graph invocation failed` - OSError on metadata.json
- Step failures cascading from resource exhaustion

**Root Cause Analysis:**

1. **`ag` subprocess behavior** (`grep_search.py:261-294`):
   - `ag` (The Silver Searcher) opens many files concurrently when searching large directories
   - When system ulimit (`ulimit -n`, typically 256 on macOS) is exceeded, `ag` fails with OSError 24
   - On failure (timeout, EMFILE, spawn error), `run_grep()` returns `None` and `LocalFilesystem.grep()` surfaces a structured error — **no Python walk fallback**

2. **Concurrent grep operations**:
   - Multiple subagent steps running parallel grep operations
   - Each spawns `ag` subprocess which attempts to open hundreds of files
   - Combined load exceeds system FD limit

3. **Cascading failures**:
   - ThreadLogger, checkpoint persistence, and graph invocation all fail due to system-wide FD exhaustion

### Issue 2: LLM Connection Errors Without Proper Retry

**Symptoms from loop 2b67 log analysis:**
- `StatusAssessment failed: structured model invoke failed: Connection error` - 4 occurrences
- `PlanGeneration failed: structured model invoke failed: Connection error` - 4 occurrences
- Planner falls back to default plan after only 2 retries

**Root Cause Analysis:**

1. **Current retry handling** (`planner.py:968-977`):
   - Generic Exception catch with simple retry loop (max_retries=2)
   - No exponential backoff for transient network failures
   - Connection errors lumped with other exceptions

2. **Missing middleware coverage**:
   - `LLMRateLimitMiddleware` handles timeout and 429 but not generic connection errors
   - `NetworkToolErrorsMiddleware` only covers tool calls, not planner LLM calls
   - Planner's structured output calls (`_assess_status_with_response`, `_generate_plan`) bypass middleware

---

## Implementation Plan

### Phase 1: File Descriptor Handling (grep_search.py)

**File:** `packages/soothe/src/soothe/core/filesystem/grep_search.py`

Grep uses **`ag` or `rg` subprocesses only** (see IG-509 Resolution). There is no Python directory walk fallback.

#### Implemented

1. **`_run_grep_subprocess`** — `Popen` with temp-file stdout capture, explicit cleanup on timeout/OSError.
2. **EMFILE (errno 24)** — Logged with guidance (`ulimit -n`); returns `None` → caller returns `"grep search failed"`.
3. **Binary resolution** — `get_ag_bin()` / `get_rg_bin()` with `SOOTHE_AG_PATH`, `SOOTHE_RG_PATH`, PATH, and common install paths.

#### Removed (superseded)

- `_should_skip_ag_due_to_fd_limit()` and proactive ag skip (>200 files)
- Python walk fallback and incremental batching (former IG-510/IG-520)

<details>
<summary>Historical implementation plan (obsolete)</summary>

The original plan proposed skipping `ag` on large directories and falling back to Python walk. This was removed in favor of always using `ag`/`rg`.

</details>

---

### Phase 2: Network Resilience for Planner LLM Calls

**File:** `packages/soothe/src/soothe/sloop/planning/planner.py`

#### Change 2.1: Add connection error detection helper

```python
# Near line 30 (imports section)
import httpx

def _is_transient_network_error(exc: Exception) -> bool:
    """Detect transient network errors that warrant retry with backoff."""
    # Connection errors
    exc_type_name = type(exc).__name__
    if exc_type_name in ("ConnectionError", "ConnectError", "NetworkError"):
        return True

    # httpx specific
    if isinstance(exc, httpx.ConnectError):
        return True
    if isinstance(exc, httpx.ReadTimeout):
        return True
    if isinstance(exc, httpx.WriteTimeout):
        return True

    # Check for connection-related keywords
    error_str = str(exc).lower()
    transient_keywords = [
        "connection error",
        "connection refused",
        "connection reset",
        "network unreachable",
        "timeout",
        "timed out",
        "socket error",
        "ssl error",
        "tls error",
        "eof occurred in violation of protocol",
    ]
    return any(kw in error_str for kw in transient_keywords)
```

#### Change 2.2: Add exponential backoff helper

```python
def _calculate_backoff_delay(attempt: int, base: float = 1.0, max_delay: float = 30.0) -> float:
    """Calculate exponential backoff: base * 2^attempt, capped at max."""
    delay = base * (2 ** attempt)
    return min(delay, max_delay)
```

#### Change 2.3: Enhanced retry in `_assess_status_with_response`

Replace the generic Exception handler with connection-error-aware retry:

```python
# Around line 702-742
except asyncio.CancelledError:
    raise
except Exception as e:
    # Check if this is a transient network error
    if _is_transient_network_error(e):
        # Retry with exponential backoff (up to 3 times)
        for attempt in range(3):
            backoff = _calculate_backoff_delay(attempt, base=2.0, max_delay=15.0)
            logger.warning(
                "[LLMPlanner] StatusAssessment network error (attempt %d/3): %s - retrying in %.1fs",
                attempt + 1,
                str(e)[:100],
                backoff,
            )
            await asyncio.sleep(backoff)
            try:
                assessment = await model.ainvoke(messages, config=lf_cfg)
                # ... success handling
                return assessment, assessment
            except Exception as retry_exc:
                if not _is_transient_network_error(retry_exc):
                    break  # Non-transient error, stop retrying
                e = retry_exc
                continue

        # All retries exhausted, fall through to fallback
        logger.error("[LLMPlanner] StatusAssessment network error after 3 retries")

    # Non-network error or retries exhausted
    logger.warning("[LLMPlanner] StatusAssessment failed: %s", str(e)[:200])
    # ... existing fallback logic
```

#### Change 2.4: Enhanced retry in `_generate_plan`

Same pattern for plan generation:

```python
# Around line 968-977
except Exception as e:
    # Transient network error retry
    if _is_transient_network_error(e):
        for attempt in range(3):
            backoff = _calculate_backoff_delay(attempt, base=2.0, max_delay=30.0)
            logger.warning(
                "[LLMPlanner] PlanGeneration network error (attempt %d/3): %s - retrying in %.1fs",
                attempt + 1,
                str(e)[:100],
                backoff,
            )
            await asyncio.sleep(backoff)
            try:
                plan_result = await _invoke_plan_structured_output(...)
                if plan_result is not None:
                    return plan_result, plan_result
            except Exception as retry_exc:
                if not _is_transient_network_error(retry_exc):
                    break
                e = retry_exc
                continue

        logger.error("[LLMPlanner] PlanGeneration network error after 3 retries")
        last_error = e
        # Fall through to existing fallback

    # Existing generic handling
    last_error = e
    if attempt < max_retries:
        logger.debug("[LLMPlanner] Retrying after error (attempt %d/%d)", ...)
        continue
```

---

### Phase 3: LLMRateLimitMiddleware Extension (Optional Enhancement)

**File:** `packages/soothe/src/soothe/middleware/llm_rate_limit.py`

#### Change 3.1: Add connection error retry to middleware

Extend `_is_api_rate_limit_error` pattern to connection errors:

```python
def _is_transient_connection_error(exc: Exception) -> bool:
    """Check for transient connection errors that warrant retry."""
    exc_type_name = type(exc).__name__
    transient_types = {
        "ConnectionError", "ConnectError", "NetworkError",
        "ReadTimeout", "WriteTimeout",
    }
    if exc_type_name in transient_types:
        return True

    # httpx exceptions
    if "httpx" in str(type(exc).__module__):
        if exc_type_name in ("ConnectError", "ReadTimeout", "WriteTimeout", "ConnectTimeout"):
            return True

    return False
```

#### Change 3.2: Add connection error handling to `awrap_model_call`

```python
# In the retry loop around line 691-790
connection_attempts = 0
max_connection_attempts = 3

# Add new exception handler after TimeoutError and rate limit handlers
except Exception as exc:
    if _is_transient_connection_error(exc):
        connection_attempts += 1
        if connection_attempts < max_connection_attempts:
            backoff = 2.0 * connection_attempts
            logger.warning(
                "LLM connection error (attempt %d/%d) - retrying with backoff=%.1fs (thread_id=%s)",
                connection_attempts,
                max_connection_attempts,
                backoff,
                thread_id,
            )
            await asyncio.sleep(backoff)
            continue
        else:
            logger.error(
                "LLM connection error after %d retries (thread_id=%s)",
                max_connection_attempts,
                thread_id,
            )
            raise
    elif _is_api_rate_limit_error(exc):
        # ... existing 429 handling
    else:
        # Non-transient error: propagate immediately
        raise
```

---

## Testing Plan

### Test 1: Grep subprocess handling

See `packages/soothe/tests/core/filesystem/test_grep_search.py`:

- `ag`/`rg` resolution and availability
- EMFILE and timeout return structured errors (no Python walk)
- Large single-file grep via subprocess

### Test 2: Network Error Retry

```python
# tests/unit/core/loop/planning/test_planner_network_retry.py

@pytest.mark.asyncio
async def test_assess_status_retries_on_connection_error():
    """StatusAssessment retries with backoff on transient connection errors."""
    planner = LLMPlanner(...)

    # Mock model to fail twice then succeed
    call_count = 0
    async def mock_invoke(*args, **kwargs):
        call_count += 1
        if call_count < 3:
            raise ConnectionError("Network unreachable")
        return StatusAssessment(status="continue", goal_progress="medium")

    planner._model.ainvoke = mock_invoke

    result = await planner._assess_status_with_response(...)
    assert result.status == "continue"
    assert call_count == 3  # 2 failures + 1 success

@pytest.mark.asyncio
async def test_generate_plan_retries_on_connection_error():
    """PlanGeneration retries with exponential backoff."""
    # Similar test pattern
```

---

## Configuration Impact

No configuration changes required. Both fixes are code-level resilience improvements.

---

## Migration Notes

- Backward compatible - no API changes
- Existing retry configurations in `LLMRateLimitMiddleware` remain unchanged
- Planner retry behavior enhanced but fallback behavior unchanged

---

## Acceptance Criteria

1. **FD Leak**: `ag` subprocess failures no longer cascade to ThreadLogger and checkpoint persistence
2. **FD Leak**: System with default ulimit (256) can handle parallel grep operations without exhaustion
3. **Network**: Connection errors retry up to 3 times with exponential backoff before fallback
4. **Network**: Log analysis shows retry attempts and backoff delays for transient errors
5. **Tests**: All new tests pass; existing tests unchanged

---

## References

- Log analysis: loop 2b67 in `~/.soothe/logs/soothe.log`
- Related: IG-258 (thread-local rate limiting), IG-295 (timeout retry), IG-499 (429 retry)