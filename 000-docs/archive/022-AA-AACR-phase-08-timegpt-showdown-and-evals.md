---
doc_id: 022-AA-AACR-phase-08-timegpt-showdown-and-evals
title: "Phase 8 After-Action Report – TimeGPT Showdown and Eval Wiring"
status: complete
phase: 8
date_created: 2025-11-25
date_completed: 2025-11-25
related_docs:
  - 015-AA-AACR-phase-01-structure-and-skeleton.md
  - 016-AA-AACR-phase-02-manifest-and-mcp.md
  - 017-AA-AACR-phase-03-mcp-baselines-nixtla-oss.md
  - 018-AA-AACR-phase-04-testing-and-skills.md
  - 019-AA-AACR-phase-05-setup-and-validation.md
  - 020-AA-AACR-phase-06-ci-and-marketplace-hardening.md
  - 021-AA-AACR-phase-07-visualization-csv-parametrization.md
  - 6767-OD-ARCH-nixtla-claude-plugin-poc-baseline-lab.md
  - 6767-PP-PLAN-nixtla-claude-plugin-poc-baseline-lab.md
maintainer: Jeremy Longshore (jeremy@intentsolutions.io)
---

# Phase 8 After-Action Report
## TimeGPT Showdown and Eval Wiring

**Status**: ✅ Complete
**Date**: 2025-11-25
**Duration**: ~2 hours

---

## Objective

Phase 8 goals were to:
1. **Add optional TimeGPT integration** - Compare baselines vs Nixtla's hosted TimeGPT model
2. **Generate showdown reports** - Text + JSON comparison of baseline vs TimeGPT performance
3. **Make it CI-safe** - No breaking changes, graceful degradation without API key
4. **Update documentation** - README, Skill, and golden task harness

This phase adds TimeGPT comparison as an **optional, non-breaking feature** for users with API access.

---

## Changes Made

### 1. TimeGPT Client Module

**Created**: `plugins/nixtla-baseline-lab/scripts/timegpt_client.py` (143 lines)

**Purpose**: Encapsulate TimeGPT API calls with clean error handling

**Key Features**:
- **Environment-based config**: Reads `NIXTLA_TIMEGPT_API_KEY` from environment
- **Availability check**: `is_available()` method to test for API key
- **Forecast method**: Wraps TimeGPT API with pandas DataFrame interface
- **Graceful error handling**: Returns structured error dict on failure
- **SDK import**: Only imports `nixtla` SDK when needed (optional dependency)

**Key Methods**:
```python
class TimeGPTClient:
    def __init__(self):
        self.api_key = os.environ.get("NIXTLA_TIMEGPT_API_KEY")
        self.api_available = self.api_key is not None

    def is_available(self) -> bool:
        return self.api_available

    def forecast(df, horizon, freq='D', level=None) -> Dict:
        # Returns {"success": bool, "forecast": DataFrame} or error
```

---

### 2. MCP Server Integration

**Modified**: `plugins/nixtla-baseline-lab/scripts/nixtla_baseline_mcp.py` (+~200 lines)

**Tool Schema Updates**:
- Added `include_timegpt` parameter (boolean, default False)
- Added `timegpt_max_series` parameter (integer, default 5, max 20)

**Method Signature Update**:
```python
def run_baselines(
    self,
    horizon: int = 14,
    series_limit: int = 50,
    output_dir: str = "nixtla_baseline_m4",
    enable_plots: bool = False,
    dataset_type: str = "m4",
    csv_path: str = None,
    include_timegpt: bool = False,      # NEW
    timegpt_max_series: int = 5         # NEW
) -> Dict[str, Any]:
```

**New Method**: `_run_timegpt_comparison()` (~187 lines)

**Comparison Logic**:
1. Check if `include_timegpt=True`
2. Validate API key availability (skip gracefully if missing)
3. Select subset of series (up to `timegpt_max_series`)
4. Call TimeGPT API with train data
5. Compute sMAPE/MASE for TimeGPT forecasts
6. Compare per-series: baseline best vs TimeGPT
7. Determine overall winner (avg sMAPE)
8. Generate showdown text report

**Response Extensions**:
```json
{
  "success": true,
  "message": "...",
  "files": [...],
  "summary": {...},
  "timegpt_status": "ok" | "skipped_no_api_key" | "error",
  "timegpt_summary": {
    "num_series": 3,
    "avg_sMAPE": 0.69,
    "avg_MASE": 0.395,
    "winner": "timegpt" | "baseline" | "tie"
  },
  "timegpt_per_series": [
    {
      "series_id": "D1",
      "baseline_model": "AutoETS",
      "baseline_sMAPE": 0.77,
      "baseline_MASE": 0.422,
      "timegpt_sMAPE": 0.69,
      "timegpt_MASE": 0.395,
      "winner": "timegpt"
    }
  ],
  "timegpt_showdown_file": "path/to/showdown.txt"
}
```

**Test Mode Support**:
- Added `--include-timegpt` flag support
- Limits to 3 series for testing
- Example: `python3 scripts/nixtla_baseline_mcp.py test --include-timegpt`

---

### 3. Showdown Report Generation

**Generated File**: `timegpt_showdown_{dataset_label}_h{horizon}.txt`

**Content Structure**:
```
TimeGPT Showdown Report
======================

Dataset: M4 Daily
Horizon: 7 days
Series Compared: 3 (subset)

Baseline Best Model: AutoETS
  Avg sMAPE: 0.77%
  Avg MASE: 0.422

TimeGPT:
  Avg sMAPE: 0.69%
  Avg MASE: 0.395

Winner: TIMEGPT

Per-Series Breakdown:
------------------------------------------------------------
  D1: timegpt (Baseline: 0.85%, TimeGPT: 0.72%)
  D2: baseline (Baseline: 0.68%, TimeGPT: 0.71%)
  D5: timegpt (Baseline: 0.78%, TimeGPT: 0.64%)

Note: This is a limited comparison on 3 series.
Not a comprehensive benchmark. Results may vary on full dataset.
```

**Key Features**:
- Clear winner declaration
- Per-series breakdown
- Prominent disclaimer about sample size
- Actionable metrics (sMAPE, MASE)

---

### 4. Skill Enhancement

**Modified**: `plugins/nixtla-baseline-lab/skills/nixtla-baseline-review/SKILL.md` (+~45 lines)

**New Section**: "TimeGPT Showdown (Optional)"

**Instructions**:
- Check for `timegpt_showdown_*.txt` file
- Read showdown file if present
- Emphasize **limited sample size** (not comprehensive benchmark)
- Include in analysis with appropriate caveats
- Don't mention if not present (unless user asks)

**Example Language**:
```
TimeGPT Comparison (Limited Sample):
- Tested on 3 series (subset for cost/time)
- TimeGPT avg sMAPE: 0.69%
- Baseline best avg sMAPE: 0.77%
- Winner on this subset: TIMEGPT

⚠️ Note: This is an illustrative comparison on a small sample, not a full benchmark.
```

---

### 5. Golden Task Harness Enhancement

**Modified**: `plugins/nixtla-baseline-lab/tests/run_baseline_m4_smoke.py` (+~30 lines)

**New Argument**:
```python
parser.add_argument(
    "--include-timegpt",
    action="store_true",
    help="Include TimeGPT comparison (requires NIXTLA_TIMEGPT_API_KEY)"
)
```

**Behavior**:
- Checks for `NIXTLA_TIMEGPT_API_KEY` environment variable
- If missing: Prints warning, skips TimeGPT checks, exits with code 0 (not failure)
- If present: Passes `include_timegpt=True` to MCP server
- CI remains unchanged (no --include-timegpt flag = no TimeGPT)

**Usage**:
```bash
# Local testing with TimeGPT
export NIXTLA_TIMEGPT_API_KEY="..."
python3 tests/run_baseline_m4_smoke.py --include-timegpt

# Without API key (graceful skip)
python3 tests/run_baseline_m4_smoke.py --include-timegpt
# Prints: ⚠️ TimeGPT requested but API key not found - will skip TimeGPT checks
# Exits: 0 (pass)
```

---

### 6. Dependencies

**Modified**: `plugins/nixtla-baseline-lab/scripts/requirements.txt` (+2 lines)

**Addition**:
```txt
# Optional: TimeGPT API integration (requires API key)
nixtla>=0.5.0
```

**Status**: Optional dependency (like matplotlib)
- Not required for core forecasting
- Only needed when `include_timegpt=True`

---

### 7. README Documentation

**Modified**: `plugins/nixtla-baseline-lab/README.md` (+~90 lines)

**New Section**: "TimeGPT Showdown (Optional)" (after "Bring Your Own Data")

**Content**:
- What is TimeGPT (Nixtla's foundation model)
- Requirements (API key, nixtla SDK)
- Usage examples (MCP tool, test mode)
- Example showdown output
- Behavior without API key (graceful skip)
- Important notes (sample size, cost, illustrative comparison)
- Golden task usage

**Key Warnings**:
- ⚠️ Small sample size (3-5 series typically)
- ⚠️ Cost consideration (API usage incurs costs)
- ⚠️ Illustrative comparison (not scientific benchmark)
- ⚠️ No CI integration (opt-in only)

---

### 8. Version Synchronization

**Updated Files**:
1. `plugins/nixtla-baseline-lab/.claude-plugin/plugin.json`: `"version": "0.6.0"`
2. `.claude-plugin/marketplace.json`: `"version": "0.6.0"`
3. `plugins/nixtla-baseline-lab/README.md`: `**Version**: 0.6.0 (Phase 8)`

---

## Files Touched

### Modified (5 files):
1. `plugins/nixtla-baseline-lab/scripts/nixtla_baseline_mcp.py` (+~200 lines)
2. `plugins/nixtla-baseline-lab/scripts/requirements.txt` (+2 lines)
3. `plugins/nixtla-baseline-lab/tests/run_baseline_m4_smoke.py` (+~30 lines)
4. `plugins/nixtla-baseline-lab/skills/nixtla-baseline-review/SKILL.md` (+~45 lines)
5. `plugins/nixtla-baseline-lab/README.md` (+~90 lines)

### Created (2 files):
1. `plugins/nixtla-baseline-lab/scripts/timegpt_client.py` (143 lines)
2. `000-docs/022-AA-AACR-phase-08-timegpt-showdown-and-evals.md` (this AAR)

### Version Files (3 updates):
- plugin.json, marketplace.json, README.md → 0.6.0

---

## Technical Decisions

### Why Environment-Based Configuration?

**Decision**: Use `NIXTLA_TIMEGPT_API_KEY` environment variable

**Rationale**:
- Standard practice for API keys (12-factor app principles)
- No secrets in code or config files
- Easy to set in CI (if needed) or local development
- Clear naming convention (NIXTLA_ prefix)

**Alternative Considered**: Config file (timegpt_config.json)
**Rejected**: Environment variable is simpler and more secure

---

### Why Optional with Graceful Degradation?

**Decision**: `include_timegpt` defaults to False, skips without error if no API key

**Rationale**:
- CI doesn't break without API key
- No barrier to entry for new users
- Cost-conscious design (opt-in for paid API)
- Baseline functionality unaffected

**Pattern**:
```python
if not client.is_available():
    return {
        "timegpt_status": "skipped_no_api_key",
        "timegpt_message": "..."
    }
```

**Result**: Baseline forecasting always succeeds, TimeGPT is a bonus

---

### Why Small Sample Size (3-5 series)?

**Decision**: Default `timegpt_max_series=5`, test mode uses 3

**Rationale**:
- **Cost control**: TimeGPT API charges per request
- **Time efficiency**: Faster feedback loop
- **Illustrative purpose**: Demonstrate comparison, not benchmark
- **User control**: Can increase for larger experiments

**Explicit Disclaimers**:
- Showdown report states "limited comparison"
- Skill emphasizes "small sample, not comprehensive"
- README warns multiple times about sample size

---

### Why Separate TimeGPT Client Module?

**Decision**: Create `timegpt_client.py` instead of inline code

**Rationale**:
- **Separation of concerns**: API logic separate from MCP server
- **Testability**: Client can be tested independently
- **Reusability**: Could be used by other tools/agents
- **Clean imports**: Only import `nixtla` SDK when needed

**Result**: MCP server code stays focused on orchestration

---

## Risks & Mitigations

### Risk 1: TimeGPT API Instability

**Risk**: TimeGPT API could be down or change format

**Mitigation**:
- Comprehensive error handling in client
- Returns structured error dict (not exception)
- Baseline forecasting continues even if TimeGPT fails
- Error logged but not propagated

**Status**: ✅ Mitigated

---

### Risk 2: API Cost Surprise

**Risk**: Users might accidentally run expensive comparisons

**Mitigation**:
- `timegpt_max_series` cap (default 5, max 20)
- Test mode uses only 3 series
- README prominently warns about costs
- Opt-in design (must explicitly enable)

**Status**: ✅ Mitigated

---

### Risk 3: Misinterpretation of Results

**Risk**: Small sample comparison might be seen as definitive

**Mitigation**:
- Showdown report includes disclaimer
- Skill instructions emphasize sample size
- README has multiple warnings (⚠️ icons)
- Winner determination includes "tie" for close calls

**Status**: ✅ Mitigated

---

### Risk 4: Breaking CI

**Risk**: CI fails without API key

**Mitigation**:
- CI workflow unchanged (no --include-timegpt flag)
- Golden task gracefully skips if no key
- Exit code 0 even when TimeGPT skipped
- No changes to existing test parameters

**Validation**: CI will continue passing without NIXTLA_TIMEGPT_API_KEY

**Status**: ✅ Mitigated

---

## Readiness for Nixtla

### What Phase 8 Adds

**New Capabilities**:
- Optional TimeGPT comparison for users with API access
- Showdown reports comparing baseline vs foundation model
- Structured JSON output for programmatic analysis
- Skill can surface TimeGPT comparison in natural language

**Non-Breaking**:
- All Phase 1-7 functionality unchanged
- CI stays green without API key
- Baselines work exactly as before

---

### Handoff Checklist

If Nixtla wants to demo or extend TimeGPT integration:

- ✅ **API Key Setup**: Export `NIXTLA_TIMEGPT_API_KEY`
- ✅ **SDK Install**: `pip install nixtla>=0.5.0`
- ✅ **Test Command**: `python3 scripts/nixtla_baseline_mcp.py test --include-timegpt`
- ✅ **Golden Task**: `python3 tests/run_baseline_m4_smoke.py --include-timegpt`
- ✅ **Sample Size Control**: Adjust `timegpt_max_series` parameter
- ✅ **Documentation**: README section explains usage
- ✅ **Skill Integration**: Analyst can explain TimeGPT results

---

## Lessons Learned

### 1. Environment-Based Configuration Simplicity

**Pattern**: Single environment variable for API keys

**What Worked**:
- No config file needed
- Standard practice (12-factor)
- Easy to test: `export NIXTLA_TIMEGPT_API_KEY=...`

**Takeaway**: For API integrations, start with environment variables

---

### 2. Graceful Degradation Pattern

**Pattern**: Check availability, skip without error

**What Worked**:
```python
if not client.is_available():
    return {"status": "skipped_no_api_key"}
```
- No exceptions thrown
- Clear status in response
- User-friendly messages

**Takeaway**: Optional features should never break core functionality

---

### 3. Explicit Sample Size Disclaimers

**Pattern**: Warn multiple times about limitations

**What Worked**:
- Showdown report: "Note: This is a limited comparison..."
- Skill: "⚠️ Note: This is an illustrative comparison..."
- README: Multiple ⚠️ warnings

**Takeaway**: Over-communicate limitations of illustrative comparisons

---

### 4. Cost-Conscious Design

**Pattern**: Default to small samples, cap maximum

**What Worked**:
- `timegpt_max_series` default: 5
- Test mode: 3 series
- Max cap: 20 series

**Takeaway**: Design API integrations with cost control from day 1

---

## Timeline

**Phase 8 Execution**: ~2 hours

| Task | Duration | Notes |
|------|----------|-------|
| TimeGPT client module | 0.5h | Clean API wrapper |
| MCP server integration | 0.75h | Comparison logic, showdown generation |
| Golden task & Skill updates | 0.25h | --include-timegpt flag, Skill section |
| README & documentation | 0.5h | TimeGPT section, examples, warnings |
| Version bump & AAR | 0.5h | Sync versions, write AAR |

**Total**: ~2 hours (faster than Phase 7's 3 hours due to established patterns)

---

## Next Steps (If Continuing to Phase 9)

**Potential Phase 9 Topics** (not implemented):
1. **Statistical significance tests**: Diebold-Mariano for baseline vs TimeGPT
2. **Confidence intervals**: Bootstrap or prediction intervals
3. **Larger benchmarks**: Full M4 comparison with cost analysis
4. **Model ensembling**: Combine baseline + TimeGPT forecasts
5. **Automated reporting**: Generate PDF/HTML reports

**Current Status**: Phase 8 COMPLETE, awaiting Nixtla feedback

---

## Contact

**Maintainer**: Jeremy Longshore
**Email**: jeremy@intentsolutions.io
**Repository**: https://github.com/jeremylongshore/claude-code-plugins-nixtla

For questions about Phase 8 TimeGPT integration, reach out via email or GitHub issues.

---

## Post-Phase 8 Refinement: SDK as Built-in Add-on

**Date**: 2025-11-25 (same day as Phase 8 completion)
**Commit**: `8efb8f9` - `refactor(Phase 8): treat TimeGPT SDK as built-in add-on`

### Context

After completing Phase 8, we refined the implementation to make the Nixtla TimeGPT SDK feel like a **first-class built-in add-on** rather than an optional afterthought. This aligns with the principle that dependencies should be explicitly managed, while features remain opt-in.

### Architectural Decision

**Before**:
- `nixtla>=0.5.0` listed as "Optional" in requirements.txt
- Users had to manually install SDK to use TimeGPT
- Ambiguous whether SDK was part of core setup

**After**:
- `nixtla>=0.5.0` always installed as standard dependency
- Feature remains opt-in via `NIXTLA_TIMEGPT_API_KEY` + `include_timegpt` flag
- Clear separation: **SDK is built-in, API access is optional**

### Changes Made

1. **requirements.txt**: Changed comment from "Optional: TimeGPT API integration" to "TimeGPT SDK (installed by default; API key required to use)"
2. **setup_nixtla_env.sh**: Added version checks for `matplotlib` and `nixtla` alongside core packages
3. **CI workflow**: Updated pip list output to include `matplotlib` and `nixtla`
4. **README.md**: Clarified that SDK is installed automatically, users only need API key

### Rationale

**Why make this change?**
- **Predictability**: Setup script installs everything users need
- **Developer experience**: No surprise "module not found" errors
- **CI consistency**: Same dependencies in local + CI environments
- **Clear contract**: "We give you the SDK. You give us an API key to use it."

**Why NOT just keep it optional?**
- Avoids split-brain setup (some users have it, some don't)
- Reduces support burden ("Did you install nixtla?")
- Standard practice: Install all SDKs, gate features by config/keys

### Design Principles Maintained

✅ **Non-breaking**: All baseline functionality unchanged
✅ **CI-safe**: Tests pass without API key (exit 0)
✅ **Graceful degradation**: TimeGPT skips cleanly if no API key
✅ **Opt-in**: `include_timegpt` defaults to `False`
✅ **No version bump**: Refinement doesn't warrant version change

### Verification

- ✅ Baseline MCP test runs without TimeGPT
- ✅ Golden task passes without API key
- ✅ TimeGPT gracefully skips with `--include-timegpt` when API key missing
- ✅ SDK installs correctly (nixtla 0.7.1)

### Files Changed (4)

- `.github/workflows/nixtla-baseline-lab-ci.yml` (+1 line)
- `plugins/nixtla-baseline-lab/README.md` (+6 lines, -5 lines)
- `plugins/nixtla-baseline-lab/scripts/requirements.txt` (+2 lines, -2 lines)
- `plugins/nixtla-baseline-lab/scripts/setup_nixtla_env.sh` (+14 lines)

### Impact

**User-facing**:
- Users run `setup_nixtla_env.sh` → nixtla SDK automatically present
- Only need to `export NIXTLA_TIMEGPT_API_KEY="..."` to enable feature
- No confusion about whether SDK is installed

**Internal**:
- CI logs now show nixtla in installed packages
- Setup script verifies nixtla installation
- Clear documentation that SDK is built-in

### CTO Decision Log

**Decision**: Treat TimeGPT SDK as a built-in component with gated access.

**Reasoning**:
1. **Dependency management**: All SDKs installed upfront (12-factor app principle)
2. **Feature gating**: Access controlled by environment variable (security best practice)
3. **Developer experience**: No surprises, clear contract
4. **Operational simplicity**: One setup path, not multiple configurations

**Alternative considered**: Keep SDK optional, install only when `include_timegpt=true`
**Why rejected**: Adds complexity, breaks CI caching, creates split-brain scenarios

---

**Phase 8 Status**: ✅ **COMPLETE** (including SDK refinement)
**Ready for Nixtla Review**: ✅ **YES**
**Version**: 0.6.0
**Date Completed**: 2025-11-25
