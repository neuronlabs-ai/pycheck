"""
PyCheck Rule Registry — 37 ML Safety Rules
Each rule is a self-contained checker with code, severity, and AST visitor logic.
"""

import ast
from dataclasses import dataclass
from typing import Optional, List, Dict, Set


@dataclass
class Diagnostic:
    line: int
    col: int
    severity: str  # "error" | "warning" | "info"
    code: str      # "T001", "C001", etc.
    message: str
    help: Optional[str] = None
    confidence: Optional[str] = None  # "high" | "medium" | "low"

    def to_dict(self):
        d = {"line": self.line, "col": self.col, "severity": self.severity,
             "code": self.code, "message": self.message}
        if self.help:
            d["help"] = self.help
        if self.confidence:
            d["confidence"] = self.confidence
        return d


class Rule:
    """Base class for all PyCheck rules."""
    code: str = ""
    name: str = ""
    severity: str = "warning"
    category: str = ""

    def check_node(self, node: ast.AST, context: 'AnalysisContext') -> List[Diagnostic]:
        return []

    def _get_call_name(self, node: ast.AST) -> str:
        """Extract function/method name from a Call AST node."""
        if isinstance(node, ast.Call):
            if isinstance(node.func, ast.Name):
                return node.func.id
            if isinstance(node.func, ast.Attribute):
                return node.func.attr
        return ""

    def _get_negative_value(self, arg, ctx=None):
        """Extract the absolute value from a negative numeric expression."""
        if isinstance(arg, ast.UnaryOp) and isinstance(arg.op, ast.USub):
            if isinstance(arg.operand, ast.Constant) and isinstance(arg.operand.value, (int, float)):
                return abs(arg.operand.value)
        if isinstance(arg, ast.Constant) and isinstance(arg.value, (int, float)) and arg.value < 0:
            return abs(arg.value)
        if isinstance(arg, ast.Name) and ctx is not None and hasattr(ctx, 'constants'):
            val = ctx.constants.get(arg.id)
            if val is not None and isinstance(val, (int, float)) and val < 0:
                return abs(val)
        return None

    def _has_temporal_context(self, ctx: 'AnalysisContext') -> bool:
        """AST-based temporal context detector immune to substring collisions in comments/words."""
        if not ctx or not ctx.source_lines:
            return False
        tree = getattr(ctx, 'tree', None)
        if tree is None:
            try:
                tree = ast.parse("\n".join(ctx.source_lines))
                ctx.tree = tree
            except Exception:
                return False

        temporal_call_methods = {
            'rolling', 'expanding', 'shift', 'pct_change', 'diff',
            'resample', 'merge_asof', 'to_datetime', 'date_range'
        }
        temporal_call_names = {'timeseriessplit', 'to_datetime', 'date_range',
                               'fromisoformat', 'strptime', 'strftime'}
        temporal_columns = {
            'date', 'datetime', 'timestamp', 'time', 'day', 'dt',
            'close', 'open', 'high', 'low', 'volume', 'vwap', 'ohlc',
            'adj_close', 'returns', 'ret', 'price', 'prices', 'pnl',
            'tick', 'bar', 'quotes', 'entry_date', 'exit_date',
            'trade_date', 'trade_time', 'entry_time', 'exit_time'
        }

        for node in ast.walk(tree):
            if isinstance(node, ast.Call):
                if isinstance(node.func, ast.Attribute) and node.func.attr.lower() in temporal_call_methods:
                    return True
                if isinstance(node.func, ast.Attribute) and node.func.attr == 'sort_values':
                    for arg in node.args:
                        if isinstance(arg, ast.Constant) and isinstance(arg.value, str) and arg.value.lower() in temporal_columns:
                            return True
                    for kw in node.keywords:
                        if kw.arg == 'by' and isinstance(kw.value, ast.Constant) and isinstance(kw.value.value, str) and kw.value.value.lower() in temporal_columns:
                            return True
                if isinstance(node.func, ast.Name) and node.func.id.lower() in temporal_call_names:
                    return True
                for kw in node.keywords:
                    if kw.arg == 'parse_dates':
                        return True
            if isinstance(node, ast.Subscript):
                if isinstance(node.slice, ast.Constant) and isinstance(node.slice.value, str):
                    if node.slice.value.lower() in temporal_columns:
                        return True
                if isinstance(node.slice, (ast.List, ast.Tuple)):
                    for elt in node.slice.elts:
                        if isinstance(elt, ast.Constant) and isinstance(elt.value, str):
                            if elt.value.lower() in temporal_columns:
                                return True
            if isinstance(node, ast.Constant) and isinstance(node.value, str):
                val_lower = node.value.lower()
                if any(term in val_lower for term in ('daily_prices', 'stock_prices', 'timeseries', 'time_series', 'ohlcv', 'entry_date', 'exit_date', 'trade_date', 'trade_time')):
                    return True
            # Detect datetime.fromisoformat / datetime.strptime calls
            if isinstance(node, ast.Attribute) and node.attr in ('fromisoformat', 'strptime', 'strftime'):
                return True
            # Detect 'from datetime import datetime' or 'import datetime'
            if isinstance(node, (ast.Import, ast.ImportFrom)):
                if isinstance(node, ast.ImportFrom) and node.module and 'datetime' in node.module:
                    return True
                if isinstance(node, ast.Import):
                    for alias in node.names:
                        if 'datetime' in alias.name:
                            return True
            # Detect variable names with date/time patterns
            if isinstance(node, ast.Name) and any(m in node.id.lower() for m in ('_date', 'date_', 'datetime', 'timestamp', 'trade_date', 'entry_date', 'exit_date')):
                return True

        return False

    def _has_external_temporal_context(self, ctx: 'AnalysisContext') -> bool:
        """Like _has_temporal_context but ignores rolling/shift/expanding/diff/pct_change
        calls to avoid circular suppression (these ARE the things T003/T004 check)."""
        if not ctx or not ctx.source_lines:
            return False
        tree = getattr(ctx, 'tree', None)
        if tree is None:
            try:
                tree = ast.parse("\n".join(ctx.source_lines))
            except Exception:
                return False

        temporal_columns = {
            'date', 'datetime', 'timestamp', 'time', 'day', 'dt',
            'close', 'open', 'high', 'low', 'volume', 'vwap', 'ohlc',
            'adj_close', 'returns', 'ret', 'price', 'prices', 'pnl',
            'tick', 'bar', 'quotes', 'entry_date', 'exit_date',
            'trade_date', 'trade_time', 'entry_time', 'exit_time'
        }

        for node in ast.walk(tree):
            # sort_values by date column
            if isinstance(node, ast.Call) and isinstance(node.func, ast.Attribute):
                if node.func.attr == 'sort_values':
                    for arg in node.args:
                        if isinstance(arg, ast.Constant) and isinstance(arg.value, str) and arg.value.lower() in temporal_columns:
                            return True
                    for kw in node.keywords:
                        if kw.arg == 'by' and isinstance(kw.value, ast.Constant) and isinstance(kw.value.value, str) and kw.value.value.lower() in temporal_columns:
                            return True
                if node.func.attr in ('sort', 'sort_index'):
                    return True
                if node.func.attr in ('fromisoformat', 'strptime', 'strftime'):
                    return True
            if isinstance(node, ast.Call) and isinstance(node.func, ast.Name):
                if node.func.id.lower() in ('timeseriessplit', 'to_datetime', 'date_range', 'sorted'):
                    return True
                for kw in node.keywords:
                    if kw.arg == 'parse_dates':
                        return True
            # Column name references
            if isinstance(node, ast.Subscript):
                if isinstance(node.slice, ast.Constant) and isinstance(node.slice.value, str):
                    if node.slice.value.lower() in temporal_columns:
                        return True
                if isinstance(node.slice, (ast.List, ast.Tuple)):
                    for elt in node.slice.elts:
                        if isinstance(elt, ast.Constant) and isinstance(elt.value, str):
                            if elt.value.lower() in temporal_columns:
                                return True
            if isinstance(node, ast.Constant) and isinstance(node.value, str):
                val_lower = node.value.lower()
                if any(term in val_lower for term in ('daily_prices', 'stock_prices', 'timeseries', 'time_series', 'ohlcv', 'entry_date', 'exit_date', 'trade_date', 'trade_time')):
                    return True
            # datetime imports
            if isinstance(node, (ast.Import, ast.ImportFrom)):
                if isinstance(node, ast.ImportFrom) and node.module and 'datetime' in node.module:
                    return True
                if isinstance(node, ast.Import):
                    for alias in node.names:
                        if 'datetime' in alias.name:
                            return True
            # Variable names with date patterns
            if isinstance(node, ast.Name) and any(m in node.id.lower() for m in ('_date', 'date_', 'datetime', 'timestamp', 'trade_date', 'entry_date', 'exit_date')):
                return True

        return False



class AnalysisContext:
    """Shared context for all rules during analysis."""
    def __init__(self, source_lines: List[str], filepath: str):
        self.source_lines = source_lines
        self.filepath = filepath
        self.tainted_vars: Dict[str, str] = {}  # var_name -> taint_reason
        self.fitted_before_split: Set[str] = set()
        self.has_train_test_split = False
        self.split_line: Optional[int] = None
        self.in_loop = False
        self.loop_var: Optional[str] = None
        self.assignments: Dict[str, ast.AST] = {}  # var_name -> assigned node
        self.constants: Dict[str, any] = {}  # var_name -> literal constant value
        self.train_vars: Set[str] = set()
        self.test_vars: Set[str] = set()
        self.test_contaminated_vars: Dict[str, str] = {}


# ═══════════════════════════════════════════════════════════════
#  TEMPORAL LEAK RULES (T001–T015)
# ═══════════════════════════════════════════════════════════════

class T001_ShiftNegative(Rule):
    code = "T001"
    name = "future_shift"
    severity = "error"
    category = "TemporalLeak"

    # Target/label variable names where shift(-1) is intentional (creating the prediction target)
    _TARGET_ASSIGNMENT_NAMES = {
        'label', 'labels', 'target', 'targets', 'y', 'y_true', 'y_train', 'y_test',
        'next_tok', 'next_token', 'next_word', 'next_char',
    }

    def _is_target_construction(self, node):
        """Check if this shift(-1) is assigned to a target/label variable (intentional future target, not a feature leak)."""
        parent = getattr(node, 'parent', None)
        if parent is None:
            return False
        # Direct: label = df['close'].shift(-1)
        assign = parent
        if isinstance(parent, ast.BinOp):
            assign = getattr(parent, 'parent', None)
        if isinstance(assign, ast.Assign):
            for tgt in assign.targets:
                # ONLY suppress standalone target variable assignment (e.g. label = shift(-1), next_tok = shift(-1)),
                # NEVER suppress dataframe columns like df['y'] or df['target'] (headline demo & feature leak).
                if isinstance(tgt, ast.Name) and tgt.id.lower() in self._TARGET_ASSIGNMENT_NAMES:
                    return True
        return False

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        # Standard: obj.shift(...)
        is_shift = isinstance(node.func, ast.Attribute) and node.func.attr == 'shift'
        # R2-9 fix: getattr(obj, 'shift')(...)
        is_getattr_shift = (isinstance(node.func, ast.Call) and
                            isinstance(node.func.func, ast.Name) and
                            node.func.func.id == 'getattr' and
                            len(node.func.args) >= 2 and
                            isinstance(node.func.args[1], ast.Constant) and
                            node.func.args[1].value == 'shift')
        # B10 fix: bound-method alias - sh = df['close'].shift; sh(-1)
        is_alias_shift = False
        if isinstance(node.func, ast.Name) and ctx is not None and hasattr(ctx, 'assignments'):
            assigned = ctx.assignments.get(node.func.id)
            if isinstance(assigned, ast.Attribute) and assigned.attr == 'shift':
                is_alias_shift = True
        # B5: reverse-slice cumsum — df['ret'][::-1].cumsum()[::-1]
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'cumsum':
            for child in ast.walk(node.func.value):
                if isinstance(child, ast.Slice) and isinstance(child.step, ast.UnaryOp) and isinstance(child.step.op, ast.USub):
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        ".cumsum() on reversed slice [::-1] computes cumulative future sum (lookahead bias)",
                        "Compute cumulative statistics in chronological order")]

        # B11: manual lead via np.append(arr[1:], np.nan)
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'append':
            if len(node.args) >= 2:
                arg0, arg1 = node.args[0], node.args[1]
                if isinstance(arg0, ast.Subscript) and isinstance(arg0.slice, ast.Slice):
                    if isinstance(arg0.slice.lower, ast.Constant) and isinstance(arg0.slice.lower.value, int) and arg0.slice.lower.value > 0 and arg0.slice.upper is None:
                        if (isinstance(arg1, ast.Attribute) and arg1.attr in ('nan', 'NaN')) or (isinstance(arg1, ast.Constant) and arg1.value is None):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"Manual lead via np.append(arr[{arg0.slice.lower.value}:], nan) accesses future values",
                                "Use backward lag features .shift(1)")]

        if not (is_shift or is_getattr_shift or is_alias_shift):
            return []
        results = []
        for arg in node.args:
            val = self._get_negative_value(arg, ctx)
            if val is not None and val > 0:
                # Suppress if this is intentional target/label construction
                if self._is_target_construction(node):
                    return []
                results.append(Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    f".shift(-{val}) accesses data {val} rows INTO THE FUTURE",
                    f"Use .shift({val}) to access past data instead"))
                # Taint the assignment target
                self._taint_parent(node, ctx, f"shift(-{val}) future data")
        for kw in node.keywords:
            if kw.arg == 'periods':
                val = self._get_negative_value(kw.value, ctx)
                if val is not None and val > 0:
                    if self._is_target_construction(node):
                        return []
                    results.append(Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f".shift(periods=-{val}) accesses data {val} rows INTO THE FUTURE",
                        f"Use .shift(periods={val}) to access past data instead"))
        return results

    def _get_negative_value(self, arg, ctx=None):
        if isinstance(arg, ast.UnaryOp) and isinstance(arg.op, ast.USub):
            if isinstance(arg.operand, ast.Constant) and isinstance(arg.operand.value, (int, float)):
                return abs(arg.operand.value)
        if isinstance(arg, ast.Constant) and isinstance(arg.value, (int, float)) and arg.value < 0:
            return abs(arg.value)
        if isinstance(arg, ast.Name) and ctx is not None and hasattr(ctx, 'constants'):
            val = ctx.constants.get(arg.id)
            if val is not None and isinstance(val, (int, float)) and val < 0:
                return abs(val)
        return None

    def _taint_parent(self, node, ctx, reason):
        pass  # Flow engine handles this


class T002_TrainTestSplit(Rule):
    code = "T002"
    name = "random_split_timeseries"
    severity = "error"
    category = "TemporalLeak"

    # Variable names that indicate iid (non-temporal) data, where random splits are safe
    _IID_DATA_NAMES = {
        'images', 'image', 'imgs', 'img', 'photos', 'pixels',
        'iris', 'iris_x', 'iris_y', 'iris_data', 'mnist', 'cifar',
        'texts', 'text', 'documents', 'docs', 'sentences',
        'features', 'samples', 'labels', 'categories',
    }

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        name = self._get_call_name(node)
        if name == 'train_test_split':
            ctx.has_train_test_split = True
            ctx.split_line = node.lineno

            # 1. Explicit shuffle=False is a safe chronological sequential split
            for kw in node.keywords:
                if kw.arg == 'shuffle':
                    if isinstance(kw.value, ast.Constant) and (kw.value.value is False or kw.value.value == 0):
                        return []

            # Only flag when time-series indicators exist in the data/script
            # (Claude fix: no blind name-bypass — if file has temporal markers, even 'iris' or 'images' is checked)
            if not self._has_temporal_context(ctx):
                return []

            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                "train_test_split() shuffles time-series data, leaking future into training",
                "Use a temporal split: train = data[:split_idx], test = data[split_idx:], or set shuffle=False")]
        return []



class T003_RollingBeforeSplit(Rule):
    code = "T003"
    name = "rolling_before_split"
    severity = "warning"
    category = "TemporalLeak"

    def _is_causal_rolling_zscore(self, node: ast.Call) -> bool:
        # If center=True is explicitly passed, let T003/T009 flag it
        for kw in node.keywords:
            if kw.arg == 'center':
                if isinstance(kw.value, ast.Constant) and bool(kw.value.value) is True:
                    return False
        # If node is part of a causal rolling z-score or standardization operation
        # Pattern: (x - roll.mean()) / roll.std()
        p = getattr(node, 'parent', None)
        while p is not None:
            if isinstance(p, ast.BinOp) and isinstance(p.op, (ast.Sub, ast.Div)):
                return True
            if isinstance(p, (ast.FunctionDef, ast.AsyncFunctionDef, ast.ClassDef, ast.Module)):
                break
            p = getattr(p, 'parent', None)
        return False

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'rolling':
            # center=True is always a problem (caught by T009, skip here to avoid double-flag)
            for kw in node.keywords:
                if kw.arg == 'center' and isinstance(kw.value, ast.Constant) and kw.value.value is True:
                    return []  # T009 handles this
            if self._is_causal_rolling_zscore(node):
                return []
            # In temporal/financial contexts, trailing rolling windows are almost always
            # causal (backward-looking) indicators — suppress to reduce false positives.
            if self._has_external_temporal_context(ctx):
                return []
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                ".rolling() computed on full dataset may include future data",
                "Compute rolling statistics AFTER splitting into train/test sets",
                confidence="medium")]
        return []


class T004_ExpandingBeforeSplit(Rule):
    code = "T004"
    name = "expanding_before_split"
    severity = "warning"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'expanding':
            if self._has_causal_shift_downstream(node):
                return []
            # In temporal/financial contexts, expanding windows are typically
            # causal cumulative statistics — suppress to reduce false positives.
            if self._has_external_temporal_context(ctx):
                return []
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                ".expanding() computed on full dataset may include future data",
                "Compute expanding statistics AFTER splitting into train/test sets",
                confidence="medium")]
        return []

    def _has_causal_shift_downstream(self, node):
        """Walk up the AST to see if .expanding()...agg().shift(positive) makes it causal."""
        current = node
        for _ in range(5):  # walk up max 5 levels
            parent = getattr(current, 'parent', None)
            if parent is None:
                return False
            # If parent is a .shift() call with positive arg, this is causal
            if isinstance(parent, ast.Call) and isinstance(parent.func, ast.Attribute) and parent.func.attr == 'shift':
                for arg in parent.args:
                    if isinstance(arg, ast.Constant) and isinstance(arg.value, (int, float)) and arg.value > 0:
                        return True
                # No args means shift(1) default? No, default is 1 but shift() with no args = shift(1) which IS causal
                if not parent.args and not any(kw.arg == 'periods' for kw in parent.keywords):
                    return True
            # Keep walking up through method chains (.expanding().mean() etc.)
            if isinstance(parent, ast.Attribute):
                current = parent
                continue
            if isinstance(parent, ast.Call):
                current = parent
                continue
            break
        return False


class T005_PctChangeNegative(Rule):
    code = "T005"
    name = "future_pct_change"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if not (isinstance(node.func, ast.Attribute) and node.func.attr == 'pct_change'):
            return []
        for arg in node.args:
            if isinstance(arg, ast.UnaryOp) and isinstance(arg.op, ast.USub):
                if isinstance(arg.operand, ast.Constant):
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"pct_change with negative period accesses future data",
                        "Use positive periods to look backwards in time")]
            if isinstance(arg, ast.Constant) and isinstance(arg.value, (int, float)) and arg.value < 0:
                return [Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    f"pct_change({int(arg.value)}) accesses future data",
                    "Use positive periods to look backwards in time")]
        # Also check keyword arg: pct_change(periods=-1)
        for kw in node.keywords:
            if kw.arg == 'periods':
                if isinstance(kw.value, ast.UnaryOp) and isinstance(kw.value.op, ast.USub):
                    if isinstance(kw.value.operand, ast.Constant):
                        val = kw.value.operand.value
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"pct_change(periods=-{val}) accesses future data",
                            "Use positive periods to look backwards in time")]
                if isinstance(kw.value, ast.Constant) and isinstance(kw.value.value, (int, float)) and kw.value.value < 0:
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"pct_change(periods={int(kw.value.value)}) accesses future data",
                        "Use positive periods to look backwards in time")]
                # Resolve variable reference
                if isinstance(kw.value, ast.Name) and ctx is not None and hasattr(ctx, 'constants'):
                    val = ctx.constants.get(kw.value.id)
                    if val is not None and isinstance(val, (int, float)) and val < 0:
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"pct_change(periods={int(val)}) accesses future data",
                            "Use positive periods to look backwards in time")]
        return []


class T006_FutureIndexInLoop(Rule):
    code = "T006"
    name = "future_index_loop"
    severity = "error"
    category = "TemporalLeak"

    # Column names where [i+1] access is a legitimate next-bar fill in backtesting
    _NEXT_BAR_FILL_COLUMNS = {
        'open', 'entry_price', 'open_price', 'next_open', 'fill_price',
        'entry', 'execution_price', 'exec_price', 'fill',
    }

    def _get_subscript_column(self, node):
        """Extract column name from df['col'][i+1] or col_array[i+1] patterns."""
        if isinstance(node.value, ast.Subscript):
            sl = node.value.slice
            if isinstance(sl, ast.Constant) and isinstance(sl.value, str):
                return sl.value.lower()
        if isinstance(node.value, ast.Name):
            return node.value.id.lower()
        return None

    def check_node(self, node, ctx):
        if not ctx or not ctx.in_loop:
            return []
        if not isinstance(node, ast.Subscript):
            return []
        if not ctx.in_loop or ctx.loop_var is None:
            return []
        sl = node.slice
        if isinstance(sl, ast.BinOp) and isinstance(sl.op, ast.Add):
            if self._uses_var(sl.left, ctx.loop_var) and isinstance(sl.right, ast.Constant):
                if isinstance(sl.right.value, int) and sl.right.value > 0:
                    col = self._get_subscript_column(node)
                    # Next-bar fill: accessing open[i+1] after signal on bar i is legitimate
                    if col and any(m in col for m in self._NEXT_BAR_FILL_COLUMNS):
                        return [Diagnostic(
                            node.lineno, node.col_offset, "info", self.code,
                            f"Indexing [{ctx.loop_var} + {sl.right.value}] on '{col}' — likely next-bar fill (verify signal uses bar {ctx.loop_var} data only)",
                            f"Next-bar execution is valid if the trading signal is computed from bar {ctx.loop_var} or earlier",
                            confidence="low")]
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"Indexing [{ctx.loop_var} + {sl.right.value}] inside loop accesses future data",
                        f"Only use [{ctx.loop_var}] or [{ctx.loop_var} - n] to access current/past data",
                        confidence="high")]
            if self._uses_var(sl.right, ctx.loop_var) and isinstance(sl.left, ast.Constant):
                if isinstance(sl.left.value, int) and sl.left.value > 0:
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"Indexing [{sl.left.value} + {ctx.loop_var}] inside loop may access future data",
                        f"Verify this does not access future indices",
                        confidence="medium")]
        return []

    def _uses_var(self, node, var_name):
        if isinstance(node, ast.Name) and node.id == var_name:
            return True
        return False


class T007_BackfillLeak(Rule):
    code = "T007"
    name = "backfill_leak"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr in ('fillna', 'bfill', 'backfill', 'ffill'):
            # B14: ffill on reversed frame is equivalent to bfill
            if node.func.attr == 'ffill':
                for child in ast.walk(node.func.value):
                    if isinstance(child, ast.Slice) and isinstance(child.step, ast.UnaryOp) and isinstance(child.step.op, ast.USub):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            ".ffill() on reversed slice [::-1] is equivalent to .bfill() and fills with FUTURE data",
                            "Use forward fill on chronological data")]

            if node.func.attr in ('bfill', 'backfill'):
                return [Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    f".{node.func.attr}() fills missing values with FUTURE data",
                    "Use .ffill() (forward fill) or .fillna(0) instead")]
            # Check fillna(method='bfill') or fillna(method='backfill')
            for kw in node.keywords:
                if kw.arg == 'method' and isinstance(kw.value, ast.Constant):
                    if kw.value.value in ('bfill', 'backfill'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f".fillna(method='{kw.value.value}') fills missing values with FUTURE data",
                            "Use .fillna(method='ffill') or .fillna(0) instead")]
        return []


class T008_NonCausalInterpolate(Rule):
    code = "T008"
    name = "noncausal_interpolate"
    severity = "warning"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'interpolate':
            safe_methods = {'pad', 'ffill', 'linear', 'nearest', 'zero', 'slinear'}
            for kw in node.keywords:
                if kw.arg == 'method' and isinstance(kw.value, ast.Constant):
                    if kw.value.value in ('cubic', 'spline', 'polynomial', 'quadratic'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f".interpolate(method='{kw.value.value}') uses future data points for interpolation",
                            "Use .interpolate(method='pad') or method='linear' with limit_direction='forward'")]
                    if kw.value.value in safe_methods:
                        return []  # Explicitly safe — no diagnostic
            # No method keyword specified — default is 'linear' which can be non-causal
            return [Diagnostic(
                node.lineno, node.col_offset, "info", self.code,
                ".interpolate() may use future data depending on method",
                "Ensure method is causal (e.g., method='pad' or method='ffill')")]
        return []


class T009_CenteredRolling(Rule):
    code = "T009"
    name = "centered_rolling"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'rolling':
            for kw in node.keywords:
                if kw.arg == 'center' and isinstance(kw.value, ast.Constant) and kw.value.value is True:
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        ".rolling(center=True) uses future data on both sides of the window",
                        "Use .rolling(center=False) for causal (backward-looking) windows")]
        return []


class T010_FitBeforeSplit(Rule):
    code = "T010"
    name = "fit_before_split"
    severity = "error"
    category = "TemporalLeak"

    def _is_temporal_groupby(self, call: ast.Call) -> bool:
        """Check if groupby groups by time/date (cross-sectional at each timestamp) rather than by asset/symbol."""
        if not call.args:
            return False
        first_arg = call.args[0]
        date_markers = {'date', 'dt', 'time', 'timestamp', 'ts', 'datetime', 'period'}

        def is_date_key(n: ast.AST) -> bool:
            if isinstance(n, ast.Constant) and isinstance(n.value, str):
                val = n.value.lower()
                return any(m == val or m in val.split('_') for m in date_markers)
            if isinstance(n, ast.Attribute) and n.attr.lower() in ('index', 'date', 'dt'):
                return True
            if isinstance(n, ast.Subscript) and isinstance(n.slice, ast.Constant) and isinstance(n.slice.value, str):
                val = str(n.slice.value).lower()
                return any(m == val or m in val.split('_') for m in date_markers)
            if isinstance(n, ast.Call):
                name = getattr(n.func, 'id', getattr(n.func, 'attr', ''))
                if 'grouper' in name.lower():
                    return True
            return False

        if isinstance(first_arg, (ast.List, ast.Tuple)):
            return any(is_date_key(elt) for elt in first_arg.elts)
        return is_date_key(first_arg)

    def _is_windowed_or_grouped(self, node: ast.AST) -> bool:
        """Check if an expression involves causal rolling, expanding, or temporal groupby operations (including inside lambdas)."""
        if node is None:
            return False
        # If the window operation is non-causal (e.g. center=True or lookahead shift), do not exempt it
        for child in ast.walk(node):
            if isinstance(child, ast.Call) and isinstance(child.func, ast.Attribute):
                if child.func.attr == 'rolling':
                    if any(kw.arg == 'center' and getattr(kw.value, 'value', None) is True for kw in child.keywords):
                        return False
                if child.func.attr == 'shift':
                    if child.args:
                        first_arg = child.args[0]
                        if isinstance(first_arg, ast.UnaryOp) and isinstance(first_arg.op, ast.USub):
                            return False
                    for kw in child.keywords:
                        if kw.arg == 'periods':
                            if isinstance(kw.value, ast.UnaryOp) and isinstance(kw.value.op, ast.USub):
                                return False

        for child in ast.walk(node):
            if isinstance(child, ast.Call) and isinstance(child.func, ast.Attribute):
                if child.func.attr in ('rolling', 'expanding', 'resample'):
                    return True
                if child.func.attr == 'groupby' and self._is_temporal_groupby(child):
                    return True
        # Trace upwards to see if inside lambda passed to transform/apply/agg on a groupby/rolling
        cur = node
        while cur is not None:
            parent = getattr(cur, 'parent', None)
            if isinstance(parent, ast.Call) and isinstance(parent.func, ast.Attribute):
                if parent.func.attr in ('transform', 'apply', 'agg', 'aggregate'):
                    for sub in ast.walk(parent.func.value):
                        if isinstance(sub, ast.Call) and isinstance(sub.func, ast.Attribute):
                            if sub.func.attr == 'rolling' and any(kw.arg == 'center' and getattr(kw.value, 'value', None) is True for kw in sub.keywords):
                                return False
                            if sub.func.attr in ('rolling', 'expanding', 'resample'):
                                return True
                            if sub.func.attr == 'groupby' and self._is_temporal_groupby(sub):
                                return True
            cur = parent
        return False

    def _is_train_data(self, node, ctx=None):
        """Recursively check if an AST node represents training data."""
        var_name = self._get_obj_name(node)
        if var_name and ctx is not None:
            base_var = var_name.split('.')[0]
            if hasattr(ctx, 'test_contaminated_vars') and base_var in ctx.test_contaminated_vars:
                return False
            if hasattr(ctx, 'test_vars') and base_var in ctx.test_vars:
                return False
            if hasattr(ctx, 'train_vars') and base_var in ctx.train_vars:
                return True

        train_markers = ('_train', 'train_', 'x_train', 'y_train', 'x_tr', 'y_tr', '_trn', 'trn_', 'train')
        if isinstance(node, ast.Name):
            return any(m in node.id.lower() for m in train_markers)
        if isinstance(node, ast.Subscript):
            return self._is_train_data(node.value, ctx)
        if isinstance(node, ast.Attribute):
            return self._is_train_data(node.value, ctx)
        return False

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        # Fillna with full-sample mean/median/std before split (exempt rolling/expanding/grouped)
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'fillna':
            for arg in node.args:
                if isinstance(arg, ast.Call) and isinstance(arg.func, ast.Attribute) and arg.func.attr in ('mean', 'median', 'std'):
                    if not self._is_windowed_or_grouped(arg) and not self._is_train_data(arg.func.value, ctx):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f".fillna({arg.func.attr}()) computes full-sample statistic on full dataset before train/test split",
                            "Compute mean/median only on training split, or use rolling windows / ffill()")]

        # Manual scaling / normalization on un-split dataset (z-score, min-max, demean)
        if isinstance(node.func, ast.Attribute) and node.func.attr in ('std', 'var', 'min', 'max', 'mean'):
            val = node.func.value
            if not self._is_windowed_or_grouped(val) and not self._is_train_data(val, ctx):
                parent = getattr(node, 'parent', None)
                if parent is not None and isinstance(parent, ast.BinOp):
                    # Z-score / variance scaling: / std()
                    if isinstance(parent.op, ast.Div) and node.func.attr in ('std', 'var'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            "Manual full-sample z-score (.std() / .mean()) computed on un-split dataset leaks test statistics",
                            "Compute statistics only on training partition (e.g. X_train.std()), or use expanding windows / causal cross-sectional adjustment (e.g. groupby(['date', ...]))")]
                    # Min-Max scaling: / (max - min) or - min()
                    if node.func.attr in ('min', 'max'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            "Manual full-sample min-max scaling (.min() / .max()) computed on un-split dataset leaks test extremes",
                            "Fit MinMaxScaler only on training partition, then transform test partition")]
                    # Demean: x - x.mean() (when not part of a division by std)
                    if node.func.attr == 'mean' and isinstance(parent.op, ast.Sub):
                        grandparent = getattr(parent, 'parent', None)
                        if not (grandparent is not None and isinstance(grandparent, ast.BinOp) and isinstance(grandparent.op, ast.Div)):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                "Full-sample demeaning (x - x.mean()) computed on un-split dataset leaks test mean",
                                "Compute mean only on training partition, then subtract from train and test")]

        # Full-sample quantile clipping / winsorization before split (lookahead)
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'quantile':
            cur = node
            is_printed = False
            while cur is not None:
                p = getattr(cur, 'parent', None)
                if isinstance(p, ast.Call) and isinstance(p.func, ast.Name) and p.func.id in ('print', 'display'):
                    is_printed = True
                    break
                if isinstance(p, ast.Expr):
                    is_printed = True
                    break
                cur = p

            if not is_printed:
                val = node.func.value
                if not self._is_windowed_or_grouped(val) and not self._is_train_data(val, ctx):
                    if self._is_simulation_output(val, ctx):
                        return []
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        "Full-sample quantile (.quantile()) computed on un-split dataset leaks test statistics",
                        "Compute quantiles only on training split, then use them to clip/winsorize train and test",
                        confidence="medium")]

        # Full-sample quantile binning (pd.qcut()) or percentile calculation (np.percentile())
        if isinstance(node.func, (ast.Attribute, ast.Name)):
            c_name = node.func.attr if isinstance(node.func, ast.Attribute) else node.func.id
            if c_name == 'qcut' and node.args:
                val = node.args[0]
                if not self._is_train_data(val, ctx):
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        "Full-sample quantile binning (pd.qcut()) on un-split dataset leaks future bin boundaries",
                        "Compute quantile bins only on training partition, then apply cut points to test data",
                        confidence="high")]
            if c_name in ('percentile', 'nanpercentile') and node.args:
                val = node.args[0]
                if not self._is_train_data(val, ctx):
                    # Suppress for Monte Carlo / bootstrap / simulation output
                    if self._is_simulation_output(val, ctx):
                        return []
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"Full-sample percentile (np.{c_name}()) computed on un-split dataset leaks test statistics",
                        "Compute percentiles only on training partition, then use thresholds to clip",
                        confidence="medium")]

        # Full-sample rank normalization before split (lookahead)
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'rank':
            val = node.func.value
            if not self._is_windowed_or_grouped(val) and not self._is_train_data(val, ctx):
                is_pct = any(kw.arg == 'pct' and getattr(kw.value, 'value', None) is True for kw in node.keywords)
                if is_pct:
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        ".rank(pct=True) computes full-sample percentile rank across un-split dataset (lookahead bias)",
                        "Compute percentile rank within rolling windows, group by date, or fit quantiles on training split only")]

        if isinstance(node.func, ast.Attribute) and node.func.attr in ('fit', 'fit_transform'):
            # Only flag on objects that look like ML preprocessors/models
            # Skip: fig.fit(), layout.fit(), etc.
            obj_name = self._get_obj_name(node.func.value)
            safe_objects = {'fig', 'figure', 'ax', 'axes', 'plt', 'layout',
                            'canvas', 'widget', 'app', 'db', 'session', 'socket',
                            'parser', 'formatter', 'logger', 'handler'}
            if obj_name and obj_name.lower() in safe_objects:
                return []

            # If arguments are contaminated, Flow engine F002 emits specific data contamination diagnostics
            if ctx is not None and hasattr(ctx, 'test_contaminated_vars'):
                for a in node.args:
                    v_name = self._get_obj_name(a)
                    if v_name and v_name.split('.')[0] in ctx.test_contaminated_vars:
                        return []
            
            # Suppress if all positional arguments are clearly train-only variables
            # (e.g. X_train, y_train, train_df[features], X_tr)
            if node.args and all(self._is_train_data(a, ctx) for a in node.args):
                return []

            if node.func.attr == 'fit':
                preprocessor_markers = ('scale', 'scaler', 'pca', 'select', 'encoder', 'pipe', 'pipeline', 'imput', 'trans', 'norm')
                is_preproc = obj_name and any(m in obj_name.lower() for m in preprocessor_markers)
                
                # Preprocessors (PCA, SelectKBest, Scaler) fit on full data before CV/split are definite leaks
                if is_preproc:
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"Preprocessor '{obj_name}.fit()' on full dataset leaks test statistics",
                        "Fit preprocessor only on training partition (e.g. inside cross-validation pipeline)")]

                # For final ML models (model.fit), only warn if a train/test split, CV, or test partition exists in file
                has_split_or_test = False
                if ctx is not None:
                    if getattr(ctx, 'has_train_test_split', False) or getattr(ctx, 'split_line', None) is not None:
                        has_split_or_test = True
                    if getattr(ctx, 'test_vars', None):
                        has_split_or_test = True
                    # Check for CV in source lines
                    src_text = "\n".join(ctx.source_lines)
                    if any(cv_marker in src_text for cv_marker in ('cross_val', 'cross_validate', 'KFold', 'TimeSeriesSplit', 'cv=')):
                        has_split_or_test = True
                if not has_split_or_test:
                    return []
                # Final refit after holdout evaluation is legitimate
                if self._is_final_refit(node, ctx):
                    return [Diagnostic(
                        node.lineno, node.col_offset, "info", self.code,
                        "Full-data .fit() detected after holdout evaluation — ensure holdout metrics are your deployment decision signal",
                        "This is a common pattern: evaluate on holdout, then retrain on all data for deployment",
                        confidence="low")]
                return [Diagnostic(
                    node.lineno, node.col_offset, "warning", self.code,
                    ".fit() may be called on the full dataset including test data",
                    "Call .fit() only on training data, use .transform() on test data",
                    confidence="medium")]
            else:
                return [Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    ".fit_transform() on full dataset leaks test statistics into training",
                    "Use .fit(X_train).transform(X_train), then .transform(X_test) separately")]
        return []

    def _is_simulation_output(self, node, ctx=None):
        """Check if a value comes from Monte Carlo simulation, bootstrap, or model predictions."""
        sim_markers = {'sim', 'sims', 'simulation', 'simulations', 'monte', 'monte_carlo',
                        'bootstrap', 'boot', 'samples', 'perturbation', 'perturbations',
                        'boot_probs', 'boot_returns', 'sim_results', 'mc_results',
                        'resampled', 'noise', 'replications'}
        pred_markers = {'probs', 'probabilities', 'predictions', 'preds', 'pred_probs',
                         'boot_probs', 'cv_probs', 'hold_probs', 'pred_returns'}
        if isinstance(node, ast.Name):
            name_lower = node.id.lower()
            if name_lower in sim_markers or any(m in name_lower for m in ('sim_', '_sim', 'boot_', '_boot', 'monte_', 'mc_')):
                return True
            if name_lower in pred_markers:
                return True
        if isinstance(node, ast.Subscript):
            return self._is_simulation_output(node.value, ctx)
        return False

    def _is_final_refit(self, node, ctx):
        """Check if .fit() on full data follows a holdout evaluation (legitimate final refit).
        The holdout evaluation must appear BEFORE this .fit() call in the source.
        Requires actual metric CALLS (not just imports) and holdout variable ASSIGNMENTS."""
        if ctx is None or not ctx.source_lines:
            return False
        fit_line = node.lineno
        # Only look at source lines BEFORE the .fit() call, excluding import lines
        preceding_lines = []
        for line in ctx.source_lines[:fit_line - 1]:
            stripped = line.strip()
            if stripped.startswith(('import ', 'from ')):
                continue
            preceding_lines.append(line)
        preceding_src = "\n".join(preceding_lines)
        # Pattern: holdout variables assigned + metric calls preceding this fit
        has_holdout_eval = any(m in preceding_src for m in (
            'holdout', 'hold_out', 'temporal_holdout', 'TEMPORAL_HOLDOUT',
            'X_hold', 'y_hold', 'X_test', 'y_test'))
        has_score_or_metric = any(m in preceding_src for m in (
            'roc_auc_score(', 'accuracy_score(', 'brier_score(', 'mean_absolute_error(',
            'f1_score(', 'precision_score(', 'recall_score(', '.score(', 'holdout_metrics'))
        return has_holdout_eval and has_score_or_metric

    def _get_obj_name(self, node):
        if isinstance(node, ast.Name):
            return node.id
        if isinstance(node, ast.Attribute):
            return node.attr
        if isinstance(node, ast.Call):
            return self._get_call_name(node)
        return None


class T011_ScalerBeforeSplit(Rule):
    code = "T011"
    name = "scaler_before_split"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        scaler_names = {'StandardScaler', 'MinMaxScaler', 'RobustScaler',
                        'MaxAbsScaler', 'Normalizer', 'QuantileTransformer',
                        'PowerTransformer'}
        if isinstance(node.func, ast.Name) and node.func.id in scaler_names:
            # Suppress when used inside sklearn Pipeline/make_pipeline (the pipeline handles fit/transform correctly in CV)
            parent = getattr(node, 'parent', None)
            if parent is not None:
                # Direct tuple element inside Pipeline steps list
                if isinstance(parent, ast.Tuple):
                    grandparent = getattr(parent, 'parent', None)
                    if grandparent is not None and isinstance(grandparent, ast.List):
                        ggp = getattr(grandparent, 'parent', None)
                        if ggp is not None and isinstance(ggp, ast.Call):
                            if isinstance(ggp.func, ast.Name) and ggp.func.id in ('Pipeline', 'make_pipeline'):
                                return []
                # make_pipeline(StandardScaler(), Ridge()) — direct arg
                if isinstance(parent, ast.Call):
                    if isinstance(parent.func, ast.Name) and parent.func.id in ('Pipeline', 'make_pipeline'):
                        return []
            return [Diagnostic(
                node.lineno, node.col_offset, "info", self.code,
                f"{node.func.id}() — ensure this is fit ONLY on training data",
                "Fit the scaler on X_train, then transform both X_train and X_test")]
        return []


class T012_KFoldTimeSeries(Rule):
    code = "T012"
    name = "kfold_timeseries"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        kfold_names = {'KFold', 'StratifiedKFold', 'RepeatedKFold', 'ShuffleSplit'}
        name = ""
        if isinstance(node.func, ast.Name):
            name = node.func.id
        elif isinstance(node.func, ast.Attribute):
            name = node.func.attr
        if name in kfold_names:
            # Only flag when temporal/financial context markers exist in the script
            if not self._has_temporal_context(ctx):
                return []
            # Skip if shuffle=True is explicit â T020 handles that case with a more specific message
            for kw in node.keywords:
                if kw.arg == 'shuffle' and isinstance(kw.value, ast.Constant) and kw.value.value is True:
                    return []
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                f"{name}() shuffles time-series data across folds, leaking future into training",
                "Use TimeSeriesSplit() for temporal cross-validation")]
        return []




class T013_ResampleBeforeSplit(Rule):
    code = "T013"
    name = "resample_before_split"
    severity = "warning"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'resample':
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                ".resample() on full dataset may leak future aggregate statistics",
                "Resample AFTER splitting into train/test sets")]
        return []


class T014_DiffNegative(Rule):
    code = "T014"
    name = "future_diff"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if not (isinstance(node.func, ast.Attribute) and node.func.attr == 'diff'):
            return []
        results = []
        for arg in node.args:
            val = self._get_negative_value(arg, ctx)
            if val is not None and val > 0:
                results.append(Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    f".diff(-{val}) computes difference using future data",
                    f"Use .diff({val}) to compute backward differences"))
        for kw in node.keywords:
            if kw.arg == 'periods':
                val = self._get_negative_value(kw.value, ctx)
                if val is not None and val > 0:
                    results.append(Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f".diff(periods=-{val}) computes difference using future data",
                        f"Use .diff(periods={val}) to compute backward differences"))
        return results



class T015_GroupbyShiftLeak(Rule):
    code = "T015"
    name = "groupby_shift_leak"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr in ('shift', 'diff', 'pct_change'):
            # Check if this is chained after .transform() or .apply()
            obj = node.func.value
            if isinstance(obj, ast.Call) and isinstance(obj.func, ast.Attribute):
                if obj.func.attr in ('transform', 'apply'):
                    for arg in node.args:
                        if isinstance(arg, ast.UnaryOp) and isinstance(arg.op, ast.USub):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"Negative {node.func.attr}() inside groupby().transform() leaks future within groups",
                                "Use positive periods for backward-looking operations within groups")]
        return []


class T016_MergeAsofDirection(Rule):
    code = "T016"
    name = "merge_asof_future_direction"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        is_merge_asof = False
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'merge_asof':
            is_merge_asof = True
        elif isinstance(node.func, ast.Name) and node.func.id == 'merge_asof':
            is_merge_asof = True
        
        if not is_merge_asof:
            return []
        
        for kw in node.keywords:
            if kw.arg == 'direction':
                if isinstance(kw.value, ast.Constant) and isinstance(kw.value.value, str):
                    val = kw.value.value.lower()
                    if val in ('nearest', 'forward'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"pd.merge_asof() with direction='{kw.value.value}' matches future timestamps (lookahead bias)",
                            "Use direction='backward' for point-in-time causal event joins")]
        return []


class T017_TargetLaundering(Rule):
    code = "T017"
    name = "target_laundering_leak"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        target_col_names = {'target', 'success', 'outcome', 'label', 'labels', 'y',
                            'profit', 'pnl', 'win', 'return', 'returns', 'future_price'}
        train_markers = ('_train', 'train_', 'x_train', 'y_train', 'x_tr', 'y_tr', '_trn', 'trn_', 'train', 'fit', 'fit_', '_fit', 'trn')
        test_markers = ('_test', 'test_', 'x_test', 'y_test', 'x_val', 'y_val', '_val', 'val_', '_eval', 'eval_', 'holdout', 'validation')
        
        # 1. Detect target encoding / aggregation: df.groupby(...)['target'].transform('mean')
        if isinstance(node, ast.Call):
            if isinstance(node.func, ast.Name) and node.func.id in ('TargetEncoder', 'CatBoostEncoder'):
                return [Diagnostic(
                    node.lineno, node.col_offset, "info", self.code,
                    f"{node.func.id}() calculates target statistics across groups; ensure it is fit ONLY on training data",
                    "Fit target encoders strictly on X_train, y_train after temporal splitting")]
            
            if isinstance(node.func, ast.Attribute) and node.func.attr in ('transform', 'mean', 'median', 'std', 'sum', 'agg', 'apply'):
                val = node.func.value
                col_name = None
                groupby_call = None
                
                if isinstance(val, ast.Subscript):
                    if isinstance(val.slice, ast.Constant) and isinstance(val.slice.value, str):
                        col_name = val.slice.value.lower()
                    groupby_call = val.value
                elif isinstance(val, ast.Call):
                    groupby_call = val
                
                if col_name and any(t in col_name for t in target_col_names):
                    if isinstance(groupby_call, ast.Call) and isinstance(groupby_call.func, ast.Attribute) and groupby_call.func.attr == 'groupby':
                        # Check the caller of groupby:
                        caller_obj = groupby_call.func.value
                        caller_name = ""
                        if isinstance(caller_obj, ast.Name):
                            caller_name = caller_obj.id.lower()
                        elif isinstance(caller_obj, ast.Attribute):
                            caller_name = caller_obj.attr.lower()
                        
                        # If the groupby is computed strictly within a training fold,
                        # this is a VALID fold-local transformation! Do NOT flag it.
                        if any(m in caller_name for m in train_markers):
                            return []

                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"Target laundering: grouping by target/outcome column '{col_name}' across the un-split dataset leaks future test labels into features",
                            "Compute regime/group target statistics strictly within the training fold (e.g. train_df.groupby()), and map to test fold with .fillna() for unseen regimes")]

        # 2. Detect assignment creating laundered columns: df['regime_success_rate'] = ...
        if isinstance(node, ast.Assign):
            for target in node.targets:
                if isinstance(target, ast.Subscript) and isinstance(target.slice, ast.Constant) and isinstance(target.slice.value, str):
                    col = target.slice.value.lower()
                    if any(marker in col for marker in ('success_rate', 'target_enc', 'target_mean', 'regime_success')):
                        target_df = target.value
                        target_df_name = ""
                        if isinstance(target_df, ast.Name):
                            target_df_name = target_df.id.lower()
                        elif isinstance(target_df, ast.Attribute):
                            target_df_name = target_df.attr.lower()

                        # Case A: Assigning to a training fold dataframe -> valid fold-local transformation!
                        if any(m in target_df_name for m in train_markers):
                            return []

                        # Case B: Assigning to test/inference fold dataframe (e.g. test_df['regime_success_rate'] = ...)
                        if any(m in target_df_name for m in test_markers):
                            # Check if unseen regimes at inference time are handled via .fillna()
                            has_fillna = False
                            if isinstance(node.value, ast.Call):
                                if isinstance(node.value.func, ast.Attribute) and node.value.func.attr == 'fillna':
                                    has_fillna = True
                            
                            if not has_fillna:
                                return [Diagnostic(
                                    node.lineno, node.col_offset, "warning", self.code,
                                    f"Mapping target statistics to test data '{target_df_name}' without .fillna(): unseen categories/regimes at inference time will produce NaNs",
                                    "Add .fillna(train_prior_mean) to safely handle unseen categories or market regimes at inference time")]
                            return []

                        # Case C: Assigning to un-split / full dataset dataframe (df['regime_success_rate'] = ...)
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"Target laundering: column '{target.slice.value}' encodes target outcomes across full dataset",
                            "Calculate success rates and target statistics only on the training set")]
        return []


class T018_InSampleTargetEncoding(Rule):
    code = "T018"
    name = "insample_target_encoding"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        target_col_names = {'target', 'success', 'outcome', 'label', 'labels', 'y',
                            'profit', 'pnl', 'win', 'return', 'returns', 'future_price', 'default'}

        if isinstance(node, ast.Call):
            # 1. Detect TargetEncoder(cv=None) or cv=1
            if isinstance(node.func, ast.Name) and node.func.id in ('TargetEncoder', 'CatBoostEncoder', 'WOEEncoder'):
                for kw in node.keywords:
                    if kw.arg == 'cv':
                        if (isinstance(kw.value, ast.Constant) and (kw.value.value is None or kw.value.value == 1)) or \
                           (isinstance(kw.value, ast.Name) and kw.value.id in ('None',)):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"{node.func.id}(cv=None) disables out-of-fold cross-validation; target statistics will leak in-sample labels into features",
                                "Set cv>=5 (e.g. TargetEncoder(cv=5)) to enforce out-of-fold target encoding")]

            # 2. Detect groupby on target with transform('mean'/'median'/'std'/'var')
            # e.g.: train['cat_enc'] = train.groupby('category')['target'].transform('mean')
            if isinstance(node.func, ast.Attribute) and node.func.attr == 'transform':
                val = node.func.value
                col_name = None
                groupby_call = None

                if isinstance(val, ast.Subscript):
                    if isinstance(val.slice, ast.Constant) and isinstance(val.slice.value, str):
                        col_name = val.slice.value.lower()
                    groupby_call = val.value
                elif isinstance(val, ast.Call):
                    groupby_call = val

                if col_name and any(t in col_name for t in target_col_names):
                    if isinstance(groupby_call, ast.Call) and isinstance(groupby_call.func, ast.Attribute) and groupby_call.func.attr == 'groupby':
                        agg_func = None
                        if node.args:
                            arg0 = node.args[0]
                            if isinstance(arg0, ast.Constant) and isinstance(arg0.value, str):
                                agg_func = arg0.value.lower()
                            elif isinstance(arg0, ast.Attribute):
                                agg_func = arg0.attr.lower()
                            elif isinstance(arg0, ast.Name):
                                agg_func = arg0.id.lower()

                        if agg_func in ('mean', 'median', 'std', 'var'):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"In-sample target encoding leak: groupby.transform('{agg_func}') on target '{col_name}' includes row i's own label in feature i",
                                "Use Out-of-Fold (OOF) K-Fold target encoding or Leave-One-Out smoothing: ((group_sum - y) / (count - 1)) to prevent target memorization")]

            # 3. Detect mapping naive groupby target mean onto the SAME rows:
            # e.g.: train['cat_enc'] = train['cat'].map(train.groupby('cat')['target'].mean())
            if isinstance(node.func, ast.Attribute) and node.func.attr == 'map':
                if node.args:
                    arg = node.args[0]
                    if isinstance(arg, ast.Call) and isinstance(arg.func, ast.Attribute) and arg.func.attr in ('mean', 'median', 'std', 'var'):
                        call_val = arg.func.value
                        if isinstance(call_val, ast.Subscript):
                            if isinstance(call_val.slice, ast.Constant) and isinstance(call_val.slice.value, str):
                                if any(t in call_val.slice.value.lower() for t in target_col_names):
                                    gb = call_val.value
                                    if isinstance(gb, ast.Call) and isinstance(gb.func, ast.Attribute) and gb.func.attr == 'groupby':
                                        # Extract receiver DF and source DF
                                        map_df_name = ""
                                        if isinstance(node.func.value, ast.Subscript):
                                            if isinstance(node.func.value.value, ast.Name):
                                                map_df_name = node.func.value.value.id.lower()
                                        elif isinstance(node.func.value, ast.Name):
                                            map_df_name = node.func.value.id.lower()

                                        gb_df_name = ""
                                        if isinstance(gb.func.value, ast.Name):
                                            gb_df_name = gb.func.value.id.lower()

                                        # If applying to a different holdout/validation/test partition (e.g. test vs train, val vs fit in OOF),
                                        # this is legitimate out-of-fold inference! Do NOT flag as self-target leakage.
                                        test_val_markers = ('test', 'val', 'valid', 'holdout', 'eval', 'inference')
                                        if any(m in map_df_name for m in test_val_markers) and map_df_name != gb_df_name:
                                            return []
                                        if map_df_name and gb_df_name and map_df_name != gb_df_name:
                                            return []

                                        return [Diagnostic(
                                            node.lineno, node.col_offset, self.severity, self.code,
                                            f"In-sample target encoding leak: mapping naive group target mean onto same rows leaks each row's own outcome into its feature",
                                            "Compute target statistics out-of-fold (OOF) across cross-validation splits, or use leave-one-out smoothing")]
        return []


class T019_NpRollNegative(Rule):
    code = "T019"
    name = "np_roll_future"
    severity = "error"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        # Detect np.roll(arr, -N) or numpy.roll(arr, -N)
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'roll':
            obj = node.func.value
            if isinstance(obj, ast.Name) and obj.id in ('np', 'numpy'):
                if len(node.args) >= 2:
                    val = self._get_negative_value(node.args[1], ctx)
                    if val is not None and val > 0:
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"np.roll(array, -{val}) rotates data {val} positions from the FUTURE (no NaN boundary)",
                            f"Use pd.Series.shift({val}) which inserts NaN at boundaries, or slice manually")]
                # Also check keyword: shift=... (numpy uses 'shift' param)
                for kw in node.keywords:
                    if kw.arg == 'shift':
                        val = self._get_negative_value(kw.value, ctx)
                        if val is not None and val > 0:
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"np.roll(shift=-{val}) rotates data {val} positions from the FUTURE (no NaN boundary)",
                                f"Use pd.Series.shift({val}) which inserts NaN at boundaries")]
        return []



# ═══════════════════════════════════════════════════════════════
#  CAUSAL CONFUSION RULES (C001–C010)
# ═══════════════════════════════════════════════════════════════

class C001_CorrelationCausation(Rule):
    code = "C001"
    name = "correlation_causation"
    severity = "warning"
    category = "CausalConfusion"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'corr':
            # Sink-gate: suppress for exploratory display (print, .head(), .plot(), etc.)
            parent = getattr(node, 'parent', None)
            if parent is not None:
                # print(df.corr()) or display(df.corr())
                if isinstance(parent, ast.Call):
                    if isinstance(parent.func, ast.Name) and parent.func.id in ('print', 'display', 'logging'):
                        return []
                # df.corr().head(), df.corr().to_string(), etc.
                if isinstance(parent, ast.Attribute) and parent.attr in (
                    'head', 'tail', 'to_string', 'to_html', 'style', 'plot',
                    'describe', 'info', 'shape', 'values', 'round'
                ):
                    return []
                # Standalone expression (not assigned, not passed to model)
                if isinstance(parent, ast.Expr):
                    return []
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                ".corr() measures correlation, not causation — do not use for treatment/trading decisions",
                "Use causal inference methods (DoWhy, EconML) or randomized experiments")]
        return []


class C002_TargetInFeatures(Rule):
    code = "C002"
    name = "target_in_features"
    severity = "error"
    category = "CausalConfusion"

    def _get_var_origin(self, root: ast.AST, var_name: str, visited=None) -> str:
        """Trace variable back to its source dataframe across assignments, copies, and drops."""
        if visited is None:
            visited = set()
        if var_name in visited:
            return var_name
        visited.add(var_name)

        for n in ast.walk(root):
            if isinstance(n, ast.Assign):
                for t in n.targets:
                    if isinstance(t, ast.Name) and t.id == var_name:
                        cur = n.value
                        while isinstance(cur, ast.Call) and isinstance(cur.func, ast.Attribute):
                            cur = cur.func.value
                        if isinstance(cur, ast.Name):
                            if cur.id != var_name:
                                parent = self._get_var_origin(root, cur.id, visited)
                                return parent or cur.id
        return var_name

    def _call_drops_target(self, call_node: ast.Call, target_col: str, root: Optional[ast.AST] = None) -> bool:
        """Check if a specific .drop() call drops target_col."""
        def resolve_name_val(name_id: str) -> Optional[str]:
            if root is not None:
                for stmt in ast.walk(root):
                    if isinstance(stmt, ast.Assign):
                        for t in stmt.targets:
                            if isinstance(t, ast.Name) and t.id == name_id:
                                if isinstance(stmt.value, ast.Constant) and isinstance(stmt.value.value, str):
                                    return stmt.value.value
            return None

        def matches_target(arg):
            if isinstance(arg, ast.Constant) and str(arg.value) == target_col:
                return True
            if isinstance(arg, ast.Name):
                if arg.id == target_col or 'target' in arg.id.lower() or arg.id in ('y', 'label', 'labels'):
                    return True
                val = resolve_name_val(arg.id)
                if val == target_col:
                    return True
            if isinstance(arg, (ast.List, ast.Tuple, ast.Set)):
                return any(matches_target(e) for e in arg.elts)
            return False

        for a in call_node.args:
            if matches_target(a):
                return True
        for kw in call_node.keywords:
            if kw.arg in ('columns', 'labels') and matches_target(kw.value):
                return True
        return False

    def _is_target_removed(self, node: ast.AST, var_name: str, target_col: str) -> bool:
        """Check if target_col was dropped or removed from var_name, and not re-added."""
        cur = node
        while getattr(cur, 'parent', None) is not None:
            cur = cur.parent
        root = cur
        if root is None:
            return False

        target_removed = False

        for n in ast.walk(root):
            # 1. Drop calls anywhere on var_name or assigned to var_name
            if isinstance(n, ast.Call) and isinstance(n.func, ast.Attribute) and n.func.attr == 'drop':
                caller = getattr(n.func, 'value', None)
                caller_name = getattr(caller, 'id', None)
                is_var_drop = (caller_name == var_name)
                if not is_var_drop:
                    for stmt in ast.walk(root):
                        if isinstance(stmt, ast.Assign) and stmt.value == n:
                            for t in stmt.targets:
                                if isinstance(t, ast.Name) and t.id == var_name:
                                    is_var_drop = True
                if is_var_drop and self._call_drops_target(n, target_col, root):
                    target_removed = True

            # 2. del X['target'] or del X[target_col]
            elif isinstance(n, ast.Delete):
                for target in n.targets:
                    if isinstance(target, ast.Subscript) and isinstance(target.value, ast.Name) and target.value.id == var_name:
                        if isinstance(target.slice, ast.Constant) and str(target.slice.value) == target_col:
                            target_removed = True
                        if isinstance(target.slice, ast.Name) and target.slice.id == target_col:
                            target_removed = True

            # 3. X.pop('target')
            elif isinstance(n, ast.Call) and isinstance(n.func, ast.Attribute) and n.func.attr == 'pop':
                caller = getattr(n.func, 'value', None)
                if isinstance(caller, ast.Name) and caller.id == var_name:
                    if n.args and (isinstance(n.args[0], ast.Constant) and str(n.args[0].value) == target_col or isinstance(n.args[0], ast.Name) and n.args[0].id == target_col):
                        target_removed = True

            # 4. Column selection: X = X[['feat1', 'feat2']] or X = df[['feat1', 'feat2']]
            elif isinstance(n, ast.Assign):
                for t in n.targets:
                    if isinstance(t, ast.Name) and t.id == var_name:
                        if isinstance(n.value, ast.Subscript):
                            sl = n.value.slice
                            if isinstance(sl, (ast.List, ast.Tuple)):
                                cols = [e.value for e in sl.elts if isinstance(e, ast.Constant)]
                                if cols and target_col not in cols:
                                    target_removed = True

        # Check if target was subsequently re-added via assign(target=...) or X['target'] = ...
        if target_removed:
            for n in ast.walk(root):
                if isinstance(n, ast.Call) and isinstance(n.func, ast.Attribute) and n.func.attr == 'assign':
                    caller = getattr(n.func, 'value', None)
                    if isinstance(caller, ast.Name) and caller.id == var_name:
                        if any(kw.arg == target_col for kw in n.keywords):
                            return False  # Target re-added!
                elif isinstance(n, ast.Assign):
                    for t in n.targets:
                        if isinstance(t, ast.Subscript) and isinstance(t.value, ast.Name) and t.value.id == var_name:
                            if isinstance(t.slice, ast.Constant) and str(t.slice.value) == target_col:
                                return False  # Target re-added!

        return target_removed

    def check_node(self, node, ctx):
        # 1. Check model.fit(X, df['target']) where X is df or derived from df
        if isinstance(node, ast.Call) and isinstance(node.func, ast.Attribute) and node.func.attr in ('fit', 'fit_predict', 'train'):
            if len(node.args) >= 2:
                arg0, arg1 = node.args[0], node.args[1]
                target_col, target_df = None, None
                if isinstance(arg1, ast.Subscript):
                    if isinstance(arg1.value, ast.Name):
                        target_df = arg1.value.id
                    if isinstance(arg1.slice, ast.Constant):
                        target_col = str(arg1.slice.value)
                if target_df and target_col:
                    arg0_name = None
                    if isinstance(arg0, ast.Name):
                        arg0_name = arg0.id
                        cur = node
                        while getattr(cur, 'parent', None) is not None:
                            cur = cur.parent
                        root = cur
                        origin_df = self._get_var_origin(root, arg0_name)
                        if origin_df == target_df:
                            if not self._is_target_removed(node, arg0_name, target_col):
                                return [Diagnostic(
                                    node.lineno, node.col_offset, self.severity, self.code,
                                    f"Target column '{target_col}' is included in feature input '{arg0_name}' (derived from '{target_df}' without dropping target)",
                                    f"Drop target column before training: {arg0_name}.drop(columns=['{target_col}'])")]
        if not isinstance(node, ast.Subscript):
            return []

        # Sink-Gating: If used in safe exploratory / display methods, do not flag as feature leakage
        parent = getattr(node, 'parent', None)
        if parent is not None:
            if isinstance(parent, ast.Attribute) and parent.attr in (
                'head', 'tail', 'plot', 'describe', 'info', 'hist', 'boxplot',
                'shape', 'dtypes', 'columns', 'index'
            ):
                return []
            if isinstance(parent, ast.Call):
                if isinstance(parent.func, ast.Name) and parent.func.id in ('print', 'display'):
                    return []

        train_markers = ('_train', 'train_', 'x_train', 'y_train', 'x_tr', 'y_tr', '_trn', 'trn_', 'train')
        caller_name = ""
        if isinstance(node.value, ast.Name):
            caller_name = node.value.id.lower()
        elif isinstance(node.value, ast.Attribute):
            caller_name = node.value.attr.lower()

        # Detect df[['feature1', 'target']] where target-like names are used as features
        if isinstance(node.slice, ast.List):
            raw_target_names = {'target', 'y', 'label', 'labels', 'outcome', 'y_true',
                                'future_price', 'future_return', 'next_close', 'next_price'}
            laundered_target_names = {'regime_success_rate', 'success_rate'}
            for elt in node.slice.elts:
                if isinstance(elt, ast.Constant) and isinstance(elt.value, str):
                    val = elt.value.lower()
                    if val in raw_target_names:
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"Column '{elt.value}' appears to be a target variable used as a feature",
                            "Remove target/outcome columns from feature inputs to avoid data leakage")]
                    if val in laundered_target_names or val.endswith('_success_rate') or val.endswith('_target_enc'):
                        # If caller is training data (e.g. train_df[['volatility', 'regime_success_rate']]),
                        # this is a valid fold-local target encoding feature! Do NOT flag it.
                        if any(m in caller_name for m in train_markers):
                            continue
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"Column '{elt.value}' appears to be a target or target-laundered variable used as a feature across full dataset",
                            "Compute target-encoded features strictly fold-locally on training data")]
        return []


class C003_PostTreatmentVariable(Rule):
    code = "C003"
    name = "post_treatment_variable"
    severity = "warning"
    category = "CausalConfusion"

    def check_node(self, node, ctx):
        # Detect variable names that suggest post-treatment data
        if not isinstance(node, ast.Assign):
            return []
        for target in node.targets:
            if isinstance(target, ast.Subscript) and isinstance(target.slice, ast.Constant):
                col_name = str(target.slice.value).lower()
                post_indicators = ('after_', 'post_', 'result_', 'outcome_', 'response_')
                if any(col_name.startswith(p) for p in post_indicators):
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"Column '{target.slice.value}' may be a post-treatment variable",
                        "Post-treatment variables should not be used as features in causal models")]
        return []


class C004_SelectionOnOutcome(Rule):
    code = "C004"
    name = "selection_on_outcome"
    severity = "error"
    category = "CausalConfusion"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Assign):
            return []
        val = node.value
        # Detect df = df[df['profit'] > 0] patterns (survivorship bias)
        if isinstance(val, ast.Subscript) and isinstance(val.slice, ast.Compare):
            comp = val.slice
            if isinstance(comp.left, ast.Subscript) and isinstance(comp.left.slice, ast.Constant):
                col = str(comp.left.slice.value).lower()
                outcome_cols = {'profit', 'return', 'returns', 'pnl', 'outcome',
                                'survived', 'alive', 'active', 'success'}
                if col in outcome_cols:
                    return [Diagnostic(
                        node.lineno, node.col_offset, self.severity, self.code,
                        f"Filtering by outcome column '{comp.left.slice.value}' before analysis introduces survivorship bias",
                        "Include all data points, including failures, in your analysis")]
        return []


class C005_SurvivorshipBias(Rule):
    code = "C005"
    name = "survivorship_bias"
    severity = "warning"
    category = "CausalConfusion"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'dropna':
            return [Diagnostic(
                node.lineno, node.col_offset, "info", self.code,
                ".dropna() removes rows non-randomly — may introduce survivorship bias",
                "Consider imputation (.fillna()) or analyze the pattern of missing data first")]
        return []


class C006_PHacking(Rule):
    code = "C006"
    name = "p_hacking"
    severity = "warning"
    category = "CausalConfusion"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Compare):
            return []
        # Detect patterns like p_value < 0.05
        if isinstance(node.left, ast.Name):
            if 'p_val' in node.left.id.lower() or 'pvalue' in node.left.id.lower():
                return [Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    "Comparing p-values to thresholds — risk of p-hacking with multiple comparisons",
                    "Apply Bonferroni correction or use FDR control for multiple hypothesis testing")]
        return []


class C007_CorrWithoutForDecisions(Rule):
    code = "C007"
    name = "corrwith_decisions"
    severity = "warning"
    category = "CausalConfusion"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'corrwith':
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                ".corrwith() computes correlation — do not use for causal feature selection",
                "Use mutual information, SHAP values, or causal feature selection instead")]
        return []


# ═══════════════════════════════════════════════════════════════
#  UNCERTAINTY RULES (U001–U008)
# ═══════════════════════════════════════════════════════════════

class U001_PredictNoUncertainty(Rule):
    code = "U001"
    name = "predict_no_uncertainty"
    severity = "info"
    category = "UncertaintyIgnored"

    def _has_uncertainty_handling(self, ctx) -> bool:
        """Check if uncertainty handling exists in the file (predict_proba, intervals, conformal, bootstrap)."""
        if ctx is None or not getattr(ctx, 'source_lines', None):
            return False
        src_text = "\n".join(ctx.source_lines).lower()
        uncertainty_markers = (
            'predict_proba', 'predict_std', 'predict_interval', 'conformal',
            'confidence_interval', 'prediction_interval', 'quantile', 'std',
            'scipy.stats', 'bootstrap', 'mapie', 'uncertainty'
        )
        return any(m in src_text for m in uncertainty_markers)

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'predict':
            if self._has_uncertainty_handling(ctx):
                return []
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                "model.predict() returns point estimates without confidence scores",
                "Use model.predict_proba() or compute prediction intervals to quantify uncertainty")]
        return []


class U002_HardcodedThreshold(Rule):
    code = "U002"
    name = "hardcoded_threshold"
    severity = "warning"
    category = "UncertaintyIgnored"

    # Variable names that indicate model output (thresholds on these are concerning)
    _MODEL_OUTPUT_NAMES = {'prediction', 'pred', 'probability', 'prob', 'confidence',
                           'predicted', 'model_score', 'pred_prob', 'win_probability',
                           'proba', 'class_prob', 'predicted_probability'}
    # Variable names that indicate rule-based scores (thresholds on these are intentional)
    _RULE_SCORE_NAMES = {'score', 'signal', 'rating', 'rank', 'level', 'grade',
                         'trade_score', 'rule_score', 'composite_score'}

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Compare):
            return []
        if isinstance(node.left, ast.Name):
            name_lower = node.left.id.lower()
            # Only flag thresholds on model-probability outputs, not rule-based scores
            if name_lower in self._MODEL_OUTPUT_NAMES:
                for comp_val in node.comparators:
                    if isinstance(comp_val, ast.Constant) and isinstance(comp_val.value, (int, float)):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"Hardcoded threshold ({comp_val.value}) on model output '{node.left.id}' ignores prediction uncertainty",
                            "Consider using the prediction interval (ci_low/ci_high) or calibrating thresholds out-of-sample",
                            confidence="medium")]
            # For rule-based scores, only emit low-confidence info
            if name_lower in self._RULE_SCORE_NAMES:
                for comp_val in node.comparators:
                    if isinstance(comp_val, ast.Constant) and isinstance(comp_val.value, (int, float)):
                        return [Diagnostic(
                            node.lineno, node.col_offset, "info", self.code,
                            f"Fixed threshold ({comp_val.value}) on '{node.left.id}' — verify this was validated out-of-sample",
                            "If this is a deliberate strategy rule, consider documenting the rationale and sensitivity analysis",
                            confidence="low")]
        return []


class U003_NoCalibration(Rule):
    code = "U003"
    name = "no_calibration"
    severity = "warning"
    category = "UncertaintyIgnored"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'predict_proba':
            return [Diagnostic(
                node.lineno, node.col_offset, "info", self.code,
                ".predict_proba() output may not be calibrated — probabilities may not reflect true likelihoods",
                "Use CalibratedClassifierCV or check calibration with calibration_curve()")]
        return []


class U004_NoEnsemble(Rule):
    code = "U004"
    name = "single_model"
    severity = "info"
    category = "UncertaintyIgnored"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        single_models = {'LinearRegression', 'LogisticRegression', 'DecisionTreeClassifier',
                         'DecisionTreeRegressor', 'SVR', 'SVC', 'KNeighborsClassifier',
                         'SGDClassifier', 'SGDRegressor', 'Perceptron'}
        name = ""
        if isinstance(node.func, ast.Name):
            name = node.func.id
        elif isinstance(node.func, ast.Attribute):
            name = node.func.attr
        if name in single_models:
            return [Diagnostic(
                node.lineno, node.col_offset, self.severity, self.code,
                f"{name}() — single model provides no uncertainty estimate",
                "Consider ensemble methods (RandomForest, GradientBoosting) or Bayesian approaches for uncertainty")]
        return []


class U005_ScoreOnTrainOnly(Rule):
    code = "U005"
    name = "score_train_only"
    severity = "error"
    category = "UncertaintyIgnored"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'score':
            # Check if the args look like training data
            for arg in node.args:
                if isinstance(arg, ast.Name):
                    name_lower = arg.id.lower()
                    if 'train' in name_lower and 'test' not in name_lower:
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f".score({arg.id}) evaluates on training data — this is overfitting, not validation",
                            "Evaluate on held-out test data: model.score(X_test, y_test)")]
        return []


class U006_PredictInLoop(Rule):
    code = "U006"
    name = "predict_production_loop"
    severity = "error"
    category = "UncertaintyIgnored"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        if not ctx.in_loop:
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr == 'predict':
            return [Diagnostic(
                node.lineno, node.col_offset, "warning", self.code,
                ".predict() inside a loop without uncertainty check — risky for live trading/production",
                "Add confidence thresholds or uncertainty bounds before acting on predictions")]
        return []


# ═══════════════════════════════════════════════════════════════
#  DATA QUALITY RULES (D001–D007)
# ═══════════════════════════════════════════════════════════════

class D002_SilentExceptionSwallow(Rule):
    code = "D002"
    name = "silent_exception"
    severity = "warning"
    category = "DataQuality"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.ExceptHandler):
            return []
        # Check for bare `except: pass`
        if node.type is None and len(node.body) == 1:
            if isinstance(node.body[0], ast.Pass):
                return [Diagnostic(
                    node.lineno, node.col_offset, self.severity, self.code,
                    "Bare `except: pass` silently swallows errors in data pipeline",
                    "Catch specific exceptions and log or handle them properly")]
        return []


class D003_MagicNumbers(Rule):
    code = "D003"
    name = "magic_numbers"
    severity = "info"
    category = "DataQuality"

    def check_node(self, node, ctx):
        # Detect hardcoded numeric constants in function calls
        if not isinstance(node, ast.Call):
            return []
        if isinstance(node.func, ast.Attribute) and node.func.attr in ('rolling', 'shift', 'head', 'tail', 'nlargest', 'nsmallest'):
            for arg in node.args:
                if isinstance(arg, ast.Constant) and isinstance(arg.value, (int, float)):
                    if arg.value > 100 or (isinstance(arg.value, float) and arg.value != int(arg.value)):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"Magic number {arg.value} in .{node.func.attr}() — consider using a named constant",
                            "Define as a variable: WINDOW_SIZE = {arg.value}")]
        return []



class T020_ShuffledCVOnSortedData(Rule):
    """Detect shuffled cross-validation on chronologically sorted data."""
    code = "T020"
    name = "shuffled_cv_sorted_data"
    severity = "error"
    category = "TemporalLeak"

    def _file_sorts_data(self, ctx):
        """Check if the file explicitly sorts data chronologically."""
        if ctx is None or not ctx.source_lines:
            return False
        tree = getattr(ctx, 'tree', None)
        if tree is None:
            try:
                tree = ast.parse("\n".join(ctx.source_lines))
            except Exception:
                return False
        for node in ast.walk(tree):
            if isinstance(node, ast.Call) and isinstance(node.func, ast.Attribute):
                if node.func.attr in ('sort', 'sort_values', 'sort_index'):
                    return True
            if isinstance(node, ast.Call) and isinstance(node.func, ast.Name):
                if node.func.id == 'sorted':
                    return True
        return False

    def _has_shuffle_true(self, node):
        """Check if a KFold/StratifiedKFold call has shuffle=True."""
        for kw in node.keywords:
            if kw.arg == 'shuffle':
                if isinstance(kw.value, ast.Constant) and kw.value.value is True:
                    return True
        return False

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        kfold_names = {'KFold', 'StratifiedKFold', 'RepeatedKFold', 'RepeatedStratifiedKFold'}
        name = ""
        if isinstance(node.func, ast.Name):
            name = node.func.id
        elif isinstance(node.func, ast.Attribute):
            name = node.func.attr
        if name not in kfold_names:
            return []
        if not self._has_shuffle_true(node):
            return []
        if not self._has_temporal_context(ctx) and not self._file_sorts_data(ctx):
            return []
        return [Diagnostic(
            node.lineno, node.col_offset, self.severity, self.code,
            f"{name}(shuffle=True) shuffles chronologically sorted data \u2014 validation folds will contain future information",
            "Use TimeSeriesSplit or a purged walk-forward splitter for temporal data. "
            "If using CalibratedClassifierCV or cross_val_predict, pass the time-aware splitter as the cv= parameter.",
            confidence="high")]


class T021_CalibratedCVShuffled(Rule):
    """Detect CalibratedClassifierCV using a shuffled CV splitter on temporal data."""
    code = "T021"
    name = "calibrated_cv_shuffled"
    severity = "warning"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        name = ""
        if isinstance(node.func, ast.Name):
            name = node.func.id
        elif isinstance(node.func, ast.Attribute):
            name = node.func.attr
        if name != 'CalibratedClassifierCV':
            return []
        if not self._has_temporal_context(ctx):
            return []
        for kw in node.keywords:
            if kw.arg == 'cv':
                if isinstance(kw.value, ast.Call):
                    cv_name = ""
                    if isinstance(kw.value.func, ast.Name):
                        cv_name = kw.value.func.id
                    elif isinstance(kw.value.func, ast.Attribute):
                        cv_name = kw.value.func.attr
                    if cv_name in ('KFold', 'StratifiedKFold', 'RepeatedKFold'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"CalibratedClassifierCV uses {cv_name} which shuffles temporal data \u2014 calibration will be optimistic",
                            "Pass a TimeSeriesSplit or purged walk-forward splitter as cv= for honest calibration",
                            confidence="high")]
                if isinstance(kw.value, ast.Name) and ctx is not None:
                    assigned = ctx.assignments.get(kw.value.id)
                    if isinstance(assigned, ast.Call):
                        cv_name = ""
                        if isinstance(assigned.func, ast.Name):
                            cv_name = assigned.func.id
                        elif isinstance(assigned.func, ast.Attribute):
                            cv_name = assigned.func.attr
                        if cv_name in ('KFold', 'StratifiedKFold', 'RepeatedKFold'):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"CalibratedClassifierCV uses '{kw.value.id}' ({cv_name}) which shuffles temporal data \u2014 calibration will be optimistic",
                                "Pass a TimeSeriesSplit or purged walk-forward splitter as cv= for honest calibration",
                                confidence="high")]
        has_cv_arg = any(kw.arg == 'cv' for kw in node.keywords)
        if not has_cv_arg:
            return [Diagnostic(
                node.lineno, node.col_offset, "info", self.code,
                "CalibratedClassifierCV uses default CV which shuffles folds \u2014 may be incorrect for temporal data",
                "Pass cv=TimeSeriesSplit(...) for temporal data",
                confidence="medium")]
        return []


class T022_CrossValPredictShuffled(Rule):
    """Detect cross_val_predict using a shuffled CV splitter on temporal data."""
    code = "T022"
    name = "cross_val_predict_shuffled"
    severity = "warning"
    category = "TemporalLeak"

    def check_node(self, node, ctx):
        if not isinstance(node, ast.Call):
            return []
        name = ""
        if isinstance(node.func, ast.Name):
            name = node.func.id
        elif isinstance(node.func, ast.Attribute):
            name = node.func.attr
        if name not in ('cross_val_predict', 'cross_val_score', 'cross_validate'):
            return []
        if not self._has_temporal_context(ctx):
            return []
        for kw in node.keywords:
            if kw.arg == 'cv':
                if isinstance(kw.value, ast.Call):
                    cv_name = ""
                    if isinstance(kw.value.func, ast.Name):
                        cv_name = kw.value.func.id
                    elif isinstance(kw.value.func, ast.Attribute):
                        cv_name = kw.value.func.attr
                    if cv_name in ('KFold', 'StratifiedKFold', 'RepeatedKFold'):
                        return [Diagnostic(
                            node.lineno, node.col_offset, self.severity, self.code,
                            f"{name}() uses {cv_name} which shuffles temporal data \u2014 CV metrics will be optimistic",
                            "Pass cv=TimeSeriesSplit(...) for honest temporal validation",
                            confidence="high")]
                if isinstance(kw.value, ast.Name) and ctx is not None:
                    assigned = ctx.assignments.get(kw.value.id)
                    if isinstance(assigned, ast.Call):
                        cv_name = ""
                        if isinstance(assigned.func, ast.Name):
                            cv_name = assigned.func.id
                        elif isinstance(assigned.func, ast.Attribute):
                            cv_name = assigned.func.attr
                        if cv_name in ('KFold', 'StratifiedKFold', 'RepeatedKFold'):
                            return [Diagnostic(
                                node.lineno, node.col_offset, self.severity, self.code,
                                f"{name}() uses '{kw.value.id}' ({cv_name}) which shuffles temporal data \u2014 CV metrics will be optimistic",
                                "Pass cv=TimeSeriesSplit(...) for honest temporal validation",
                                confidence="high")]
        # No cv= keyword: default CV shuffles folds
        has_cv_arg = any(kw.arg == 'cv' for kw in node.keywords)
        if not has_cv_arg:
            return [Diagnostic(
                node.lineno, node.col_offset, "info", self.code,
                f"{name}() uses default CV which shuffles folds \u2014 may be incorrect for temporal data",
                "Pass cv=TimeSeriesSplit(...) for temporal data",
                confidence="medium")]
        return []


# ═══════════════════════════════════════════════════════════════
#  RULE REGISTRY
# ═══════════════════════════════════════════════════════════════

ALL_RULES: List[Rule] = [
    # Temporal Leak
    T001_ShiftNegative(),
    T002_TrainTestSplit(),
    T003_RollingBeforeSplit(),
    T004_ExpandingBeforeSplit(),
    T005_PctChangeNegative(),
    T006_FutureIndexInLoop(),
    T007_BackfillLeak(),
    T008_NonCausalInterpolate(),
    T009_CenteredRolling(),
    T010_FitBeforeSplit(),
    T011_ScalerBeforeSplit(),
    T012_KFoldTimeSeries(),
    T013_ResampleBeforeSplit(),
    T014_DiffNegative(),
    T015_GroupbyShiftLeak(),
    T016_MergeAsofDirection(),
    T017_TargetLaundering(),
    T018_InSampleTargetEncoding(),
    T019_NpRollNegative(),
    T020_ShuffledCVOnSortedData(),
    T021_CalibratedCVShuffled(),
    T022_CrossValPredictShuffled(),
    # Causal Confusion
    C001_CorrelationCausation(),
    C002_TargetInFeatures(),
    C003_PostTreatmentVariable(),
    C004_SelectionOnOutcome(),
    C005_SurvivorshipBias(),
    C006_PHacking(),
    C007_CorrWithoutForDecisions(),
    # Uncertainty
    U001_PredictNoUncertainty(),
    U002_HardcodedThreshold(),
    U003_NoCalibration(),
    U004_NoEnsemble(),
    U005_ScoreOnTrainOnly(),
    U006_PredictInLoop(),
    # Data Quality
    D002_SilentExceptionSwallow(),
    D003_MagicNumbers(),
]

RULES_BY_CODE = {r.code: r for r in ALL_RULES}
