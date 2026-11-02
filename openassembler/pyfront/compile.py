"""The actual Python-subset -> PTX compiler: ast.parse the kernel's source, walk the tree,
emit PTX text. One Python variable name gets exactly one fixed PTX register for its whole
scope (reused across loop iterations and if/else branches, same discipline as the
hand-written PTX elsewhere in this repo) -- no SSA, no phi nodes, by design: this is a
small enough subset that a classic one-register-per-variable allocator is both correct and
trivial to verify.

STATIC COMPILATION. compile_file(path) never imports or executes the user's file: it
ast-parses it, finds the top-level functions decorated @kernel / @pyfront.kernel /
@openassembler.pyfront.kernel, and resolves every name (annotations, intrinsics, `math.`)
from the file's import statements alone. A repo-wide compile therefore cannot run
arbitrary top-level code (tests/test_pyfront_semantics.py compiles a file whose top level
is `raise SystemExit`). find_kernel() is static too; compile_kernel(fn) accepts either a
live function (it re-parses the function's whole source file, so it sees the same imports)
or find_kernel's result, and emits byte-identical PTX to compile_file for the same kernel.

SEMANTICS CONTRACT. The goal is EXACT Python semantics wherever the GPU allows; every
place it can't is listed here (and nothing else is silently different):

  Integers are i32 (two's complement, wrapping). Python ints are unbounded: any i32
  overflow (x * y past 2**31, abs(-2**31), -(-2**31), -2**31 // -1) wraps on the GPU where
  Python would just grow. Integer literals outside i32 are rejected at compile time.
  Floats are f32, not Python's float64: every operation rounds to f32. A single + - * /
  sqrt on f32 inputs is bit-identical to Python computing in float64 and rounding the
  result to f32 (float64 has > 2*24+2 bits, so the double rounding is innocuous), but a
  CHAIN of operations rounds after every step, which Python does not do.
  Float literals are rounded to the nearest f32.

  a / b   true division, always f32 (i32 operands are converted with cvt.rn.f32 first,
          exact for |x| <= 2**24), emitted as div.rn.f32 -- IEEE correctly rounded, so it
          equals Python's a / b rounded to f32. Division by a constant power of two is
          emitted as the (exactly equal) multiply by its reciprocal. Python raises
          ZeroDivisionError for x / 0; the GPU returns +-inf / NaN (IEEE). A literal
          0 or 0.0 divisor is rejected at compile time.
  a // b, a % b on i32: Python FLOOR semantics (-7 // 2 == -4, -7 % 2 == 1,
          7 % -2 == -1, sign of % follows the divisor). Emitted as PTX's truncating
          div.s32 (+ a remainder) and a branch-free floor correction; a constant divisor
          stays an immediate so the backend's divide-by-constant path applies, and a
          positive power-of-two divisor becomes shr.s32 / and.b32 (which ARE floor
          semantics in two's complement). On u32 floor == truncation, so div.u32/rem.u32
          as-is. Division by zero is UNDEFINED on the GPU (Python raises); -2**31 // -1
          wraps. A literal 0 divisor is rejected at compile time.
  a // b, a % b on f32: rejected. Python's float // is floor((a - a % b) / b) computed
          with an exact fmod and special sign/zero/inf rules (e.g. 1 // 0.1 == 9.0 even
          though 1 / 0.1 == 10.0); PTX has no matching instruction and composing one from
          floor(a / b) would be wrong exactly on those edge cases.
  float(x) on i32: cvt.rn.f32.s32 (round to nearest; exact for |x| <= 2**24, Python's
          float() would be exact up to 2**53). int(x) on f32: cvt.rzi.s32.f32, truncation
          toward zero like Python. Python raises for int(nan) / int(inf) and grows past
          2**31; the GPU saturates (NaN -> 0, out-of-range -> -2**31 / 2**31-1).
          int(u32) is rejected (values >= 2**31 don't fit i32).
  min(a, b), max(a, b): two arguments of the same type. i32/u32 -> min/max PTX
          (identical to Python on ints). f32 -> setp + selp mirroring CPython's exact
          algorithm (min returns b only if b < a, else a), so NaN and -0.0/+0.0 order
          behave exactly like Python -- PTX's min.f32 differs on both (it drops NaNs
          and orders -0 < +0). abs(x): i32 as max(x, -x) (abs(-2**31) wraps), f32 as
          abs.f32 (clears the sign bit; NaN payload may be canonicalized).
  sqrt(x) / math.sqrt(x): sqrt.rn.f32, correctly rounded -- exact. sqrt of a negative
          number returns NaN where Python's math.sqrt raises ValueError; sqrt(-0.0) is -0.0
          in both. Denormal inputs are handled exactly (no flush-to-zero).
  exp, log, tanh (bare, or as math.exp / math.log / math.tanh after `import math`) and
          rsqrt are APPROXIMATE, like CUDA's __expf/__logf/tanhf fast paths:
            exp(x)   = ex2.approx.f32(x * log2(e))   (the x*log2(e) rounding grows the
                       error with |x|: CUDA documents 2 + floor(|1.173 x|) ulp
                       for __expf, which is this exact sequence)
            log(x)   = lg2.approx.f32(x) * ln(2)     (CUDA's __logf: abs error <= 2**-21.41 for x in
                       [0.5, 2], <= 3 ulp elsewhere; log(0) = -inf, log(x<0) = NaN where
                       Python raises)
            tanh(x)  = tanh.approx.f32(x)            (relative error ~2**-11, sm_75+)
            rsqrt(x) = rsqrt.approx.f32(x)           (a few ulp; pyfront-only, math has none)
          These are deliberate: they are what training kernels use (softmax, GELU,
          layernorm); an exactly rounded expf is a long software sequence.
  Comparisons: < <= > >= == on f32 are ordered (false on NaN, as in Python); != is
          true on NaN, as in Python (setp.neu). Chained comparisons are rejected.
  Conditions of if/while: comparisons, and/or (short-circuited into branches), `not`
          (folded into the branch polarity -- no predicate is materialized), a bare
          int/float (Python truthiness: != 0, NaN is true), True/False. `not` anywhere
          else (assigned, nested in arithmetic) is rejected; so are and/or used as values.
  Loops: for v in range(start, stop[, step]) with a constant non-zero step, while cond:,
          break and continue in both, nested to any depth. Bounds are evaluated once
          (Python semantics), the loop variable keeps its last value after the loop, and
          assigning to it inside the body does not change the iteration count (both via
          a hidden counter, used only when the variable is assigned in the body or
          read outside the loop). An i32 counter that would overflow (range near 2**31
          with a large step) wraps on the GPU. for/while ... else are rejected.
  Arrays: Array(f32|i32|u32) parameters (global memory), and shared memory declared at
          kernel top level as  s = shared_array(f32, 256)  (i32/u32 too; constant
          positive size; at most 48 KB in total), read/written as s[i]. Indices are i32.
          Out-of-bounds indices are not checked (Python raises IndexError; the GPU
          reads/writes whatever is there) and NEGATIVE indices do not count from the end
          (a constant negative index is rejected; a runtime one is out of bounds).
          Shared memory starts uninitialized (Python code can't observe that only
          because pyfront kernels can't run as Python).
  syncthreads() -> bar.sync 0. Every thread of the block must reach it, so it is rejected
          at compile time when it is (lexically) under control flow that depends on the
          thread index -- an if/while on tid_x(), a for with a tid-dependent bound, or
          after a tid-dependent return/break -- which would deadlock or be undefined.
          The analysis is conservative: values loaded from arrays at a tid-dependent index
          count as thread-dependent too.
  Not supported (NotSupported with the line): any other call, lists/tuples/dicts,
          strings, attribute access other than math./pyfront. intrinsics, augmented or
          plain assignment to more than one target, f16/f64, atomics, recursion, nested
          functions, lambdas, try/with, global/nonlocal. Bitwise operators and ** are
          not implemented.
"""

from __future__ import annotations

import ast
import inspect
import math
import struct
import textwrap
from dataclasses import dataclass, field
from pathlib import Path

from openassembler.pyfront.types import ArrayType, Scalar

HEADER = ".version 8.7\n.target {arch}\n.address_size 64\n\n"

_SREGS = {
    "tid_x": "%tid.x", "tid_y": "%tid.y", "tid_z": "%tid.z",
    "ctaid_x": "%ctaid.x", "ctaid_y": "%ctaid.y", "ctaid_z": "%ctaid.z",
    "ntid_x": "%ntid.x", "ntid_y": "%ntid.y", "ntid_z": "%ntid.z",
}
_INTRINSICS = _SREGS  # back-compat name
_THREAD_VARYING = {"tid_x", "tid_y", "tid_z"}       # differ between threads of one block
_MATH1 = {"sqrt", "rsqrt", "exp", "log", "tanh"}
_MATH_MODULE = {"sqrt", "exp", "log", "tanh"}       # also accepted as math.<name>
_PF_NAMES = set(_SREGS) | _MATH1 | {"shared_array", "syncthreads", "kernel", "Array",
                                    "f32", "i32", "u32"}
_BUILTINS = {"min", "max", "abs", "float", "int", "range"}

_LOG2E_F32 = 0x3FB8AA3B     # f32(log2(e)) = 1.44269502, the constant __expf multiplies by
_LN2_F32 = 0x3F317218       # f32(ln(2))   = 0.693147182
_SMEM_LIMIT = 48 * 1024     # static .shared limit per block (sm_80, without opt-in)
_I32_MIN, _I32_MAX = -(1 << 31), (1 << 31) - 1


def _f32_bits(v: float) -> int:
    try:
        return struct.unpack("<I", struct.pack("<f", v))[0]
    except OverflowError:   # |v| beyond f32 range rounds to inf, as a C float literal would
        return 0x7F800000 | (0x80000000 if v < 0 else 0)


class NotSupported(Exception):
    """Raised for any Python construct outside the compiled subset, with the source line
    (and, from compile_file, the file) attached -- we never guess at semantics we haven't
    modeled."""

    def __init__(self, msg: str, node: ast.AST | None = None, *, path: str | None = None,
                 lineno: int | None = None):
        self.msg = msg
        self.lineno = lineno if lineno is not None else getattr(node, "lineno", None)
        self.path = path
        super().__init__(self._render())

    def _render(self) -> str:
        if self.lineno is None and self.path is None:
            return self.msg
        parts = [str(self.path)] if self.path is not None else []
        if self.lineno is not None:
            parts.append(f"line {self.lineno}")
        return f"{self.msg} ({', '.join(parts)})"

    def with_path(self, path) -> "NotSupported":
        if self.path is None:
            self.path = str(path)
            self.args = (self._render(),)
        return self


# ---- static name resolution ------------------------------------------------------------------

class _Names:
    """What names in the user's file refer to, read off its import statements only (never
    by executing it). resolve() maps an expression to a canonical string:
      "pf.X"   -- openassembler.pyfront's X (from any of: bare X never rebound by an import,
                  `from openassembler.pyfront import X [as Y]`, `pf.X` after
                  `import openassembler.pyfront as pf`, `openassembler.pyfront.X`, ...)
      "math.X" -- the math module's X (needs an `import math [as m]` / `from math import X`)
      "X"      -- a bare builtin name (min, max, abs, float, int, range) not shadowed
      None     -- anything else."""

    _PF_MODULES = ("openassembler.pyfront", "openassembler.pyfront.types",
                   "openassembler.pyfront.compile")

    def __init__(self, tree: ast.AST):
        self.alias: dict[str, str] = {}        # local name -> dotted origin
        self.defined: set[str] = set()         # module-level names bound by def/class/assign
        for n in ast.walk(tree):
            if isinstance(n, ast.Import):
                for a in n.names:
                    if a.asname:
                        self.alias[a.asname] = a.name
                    else:                       # `import a.b.c` binds `a`
                        root = a.name.split(".")[0]
                        self.alias[root] = root
            elif isinstance(n, ast.ImportFrom) and n.module and not n.level:
                for a in n.names:
                    if a.name != "*":
                        self.alias[a.asname or a.name] = f"{n.module}.{a.name}"
        if isinstance(tree, ast.Module):
            for n in tree.body:
                if isinstance(n, (ast.FunctionDef, ast.AsyncFunctionDef, ast.ClassDef)):
                    self.defined.add(n.name)
                elif isinstance(n, (ast.Assign, ast.AnnAssign, ast.AugAssign)):
                    for t in (n.targets if isinstance(n, ast.Assign) else [n.target]):
                        for sub in ast.walk(t):
                            if isinstance(sub, ast.Name):
                                self.defined.add(sub.id)

    def _dotted(self, e: ast.expr) -> str | None:
        if isinstance(e, ast.Name):
            if e.id in self.alias:
                return self.alias[e.id]
            return None if e.id in self.defined else "@" + e.id      # "@": unbound bare name
        if isinstance(e, ast.Attribute):
            base = self._dotted(e.value)
            if base is None:
                return None
            return f"{base.lstrip('@')}.{e.attr}"
        return None

    def resolve(self, e: ast.expr) -> str | None:
        d = self._dotted(e)
        if d is None:
            return None
        if d.startswith("@"):                  # bare, not imported, not defined at top level
            name = d[1:]
            if name in _PF_NAMES:              # tid_x() etc. are usable without an import
                return "pf." + name
            return name if name in _BUILTINS else None
        mod, _, attr = d.rpartition(".")
        if mod in self._PF_MODULES or mod in ("pyfront", "openassembler.pyfront.types"):
            return "pf." + attr if attr in _PF_NAMES else None
        if mod == "math" and attr in _MATH_MODULE:
            return "math." + attr
        return None


def _resolve_type(ann: ast.expr, names: _Names) -> Scalar | ArrayType:
    """Resolve a parameter annotation (i32, f32, Array(f32), pf.Array(pf.i32), or the same
    as a string under `from __future__ import annotations`) from the AST -- no eval."""
    from openassembler.pyfront import types as T

    if isinstance(ann, ast.Constant) and isinstance(ann.value, str):
        try:
            ann = ast.parse(ann.value, mode="eval").body
        except SyntaxError as e:
            raise NotSupported(f"unparseable annotation {ann.value!r}", ann) from e
    r = names.resolve(ann.func if isinstance(ann, ast.Call) else ann)
    if isinstance(ann, ast.Call) and r == "pf.Array":
        if len(ann.args) != 1 or ann.keywords:
            raise NotSupported("Array(...) takes exactly one element type", ann)
        elem = _resolve_type(ann.args[0], names)
        if not isinstance(elem, Scalar):
            raise NotSupported("Array element type must be f32, i32 or u32", ann)
        return T.Array(elem)
    if not isinstance(ann, ast.Call) and r in ("pf.f32", "pf.i32", "pf.u32"):
        return getattr(T, r[3:])
    raise NotSupported(f"unsupported type annotation {ast.unparse(ann)!r} "
                       "(use i32, u32, f32 or Array(f32|i32|u32))", ann)


# ---- barrier uniformity ----------------------------------------------------------------------

class _BarrierCheck:
    """Rejects syncthreads() under thread-dependent control flow (see the module docstring).
    `varying` = names whose value may differ between threads of one block; it is grown to a
    fixpoint because loops carry values backwards. Conservative by construction: anything
    touched by a tid, by an array read at a varying index, or assigned under varying control
    flow is varying."""

    def __init__(self, fdef: ast.FunctionDef, names: _Names):
        self.names, self.fdef = names, fdef
        self.varying: set[str] = set()

    def run(self) -> None:
        while True:
            before = set(self.varying)
            self.errors: list[ast.AST] = []
            self._block(self.fdef.body, False)
            if self.varying == before:
                break
        if self.errors:
            raise NotSupported("syncthreads() is reached under thread-dependent control flow "
                               "(an if/while/for bound or early return/break that depends on "
                               "tid_x()); every thread of the block must reach the barrier, "
                               "otherwise it deadlocks or is undefined", self.errors[0])

    def _vexpr(self, e: ast.AST | None) -> bool:
        if e is None:
            return False
        for n in ast.walk(e):
            if isinstance(n, ast.Name) and n.id in self.varying:
                return True
            if isinstance(n, ast.Call) and self.names.resolve(n.func) in {f"pf.{t}" for t in _THREAD_VARYING}:
                return True
        return False

    def _assign(self, target: ast.AST, varying: bool) -> None:
        if varying and isinstance(target, ast.Name):
            self.varying.add(target.id)

    def _block(self, body: list[ast.stmt], div: bool) -> tuple[bool, bool]:
        """Returns (divergent exit that leaves the innermost loop: break/continue,
        divergent return). `div` = control flow here already depends on the thread."""
        loop_exit = ret_exit = False
        for st in body:
            d = div or loop_exit or ret_exit
            le, re_ = self._stmt(st, d)
            loop_exit |= le
            ret_exit |= re_
        return loop_exit, ret_exit

    def _stmt(self, st: ast.stmt, div: bool) -> tuple[bool, bool]:
        if isinstance(st, ast.Expr) and isinstance(st.value, ast.Call) \
                and self.names.resolve(st.value.func) == "pf.syncthreads":
            if div:
                self.errors.append(st)
            return False, False
        if isinstance(st, ast.Assign):
            for t in st.targets:
                self._assign(t, div or self._vexpr(st.value))
            return False, False
        if isinstance(st, ast.AugAssign):
            self._assign(st.target, div or self._vexpr(st.value) or self._vexpr(st.target))
            return False, False
        if isinstance(st, ast.If):
            d = div or self._vexpr(st.test)
            a = self._block(st.body, d)
            b = self._block(st.orelse, d)
            return a[0] or b[0], a[1] or b[1]
        if isinstance(st, (ast.While, ast.For)):
            hdr = st.test if isinstance(st, ast.While) else st.iter
            d = div or self._vexpr(hdr)
            if isinstance(st, ast.For):
                self._assign(st.target, d)
            le, re_ = self._block(st.body, d)
            if le or re_:              # some threads left early: later iterations diverge
                self._block(st.body, True)
            # all threads that entered the loop meet again after it (break/continue don't
            # leak out); a divergent return does: the rest of the function is divergent.
            return False, re_
        if isinstance(st, (ast.Break, ast.Continue)):
            return div, False
        if isinstance(st, ast.Return):
            return False, div
        return False, False


# ---- codegen state ----------------------------------------------------------------------------

@dataclass
class _Reg:
    name: str      # "%r3", "%f2", "%p1", "%rd1"
    kind: str      # "s32" | "u32" | "f32" | "pred" | "ptr" (ptr = 64-bit global address)


@dataclass
class _Arr:
    space: str            # "global" | "shared"
    elem: str             # "f32" | "s32" | "u32"
    base: _Reg            # %rd (global, generic->global converted) or %r (shared window offset)
    sym: str | None = None
    length: int | None = None


@dataclass
class _Scope:
    """One kernel's codegen state: register allocation, labels, output."""

    arch: str
    vars: dict[str, _Reg] = field(default_factory=dict)
    arrays: dict[str, _Arr] = field(default_factory=dict)
    params: list[tuple[str, str]] = field(default_factory=list)  # (ptx_type, name)
    shared: list[tuple[str, str, int]] = field(default_factory=list)  # (sym, ptx type, count)
    smem_bytes: int = 0
    lines: list[str] = field(default_factory=list)
    n_r: int = 0
    n_f: int = 0
    n_p: int = 0
    n_rd: int = 0
    label_n: int = 0
    exit_label: str = "L_exit"

    def emit(self, text: str) -> None:
        self.lines.append(text)

    def new_label(self, tag: str) -> str:
        self.label_n += 1
        return f"L_{tag}_{self.label_n}"

    def new_reg(self, kind: str) -> _Reg:
        if kind in ("s32", "u32"):
            self.n_r += 1
            return _Reg(f"%r{self.n_r}", kind)
        if kind == "f32":
            self.n_f += 1
            return _Reg(f"%f{self.n_f}", kind)
        if kind == "pred":
            self.n_p += 1
            return _Reg(f"%p{self.n_p}", kind)
        if kind == "ptr":
            self.n_rd += 1
            return _Reg(f"%rd{self.n_rd}", kind)
        raise ValueError(kind)

    def var_reg(self, name: str, kind: str, node: ast.AST) -> _Reg:
        """First assignment to `name` allocates its register; later ones must agree on type
        -- reassigning a scalar's type is not supported (it would need a second physical
        register, defeating the point of reusing one name across branches/iterations)."""
        if name in self.arrays:
            raise NotSupported(f"{name!r} is an array; it can't be reassigned", node)
        if name in self.vars:
            r = self.vars[name]
            if r.kind != kind:
                raise NotSupported(f"variable {name!r} reassigned with a different type "
                                   f"({r.kind} -> {kind})", node)
            return r
        r = self.new_reg(kind)
        self.vars[name] = r
        return r


def _const_value(node: ast.expr):
    """int/float value of a literal, folding unary +/- (so `-2` is a constant); else None."""
    if isinstance(node, ast.Constant) and isinstance(node.value, (int, float)) \
            and not isinstance(node.value, bool):
        return node.value
    if isinstance(node, ast.UnaryOp) and isinstance(node.op, (ast.USub, ast.UAdd)):
        v = _const_value(node.operand)
        if v is not None:
            return -v if isinstance(node.op, ast.USub) else v
    return None


def _is_pow2(v: int) -> bool:
    return v > 0 and v & (v - 1) == 0


class _Emitter:
    """One pass over the kernel body; every statement either emits PTX or raises
    NotSupported. Expressions return a _Reg holding the value (a fresh scratch register
    unless the expression is a bare variable read, which returns its home register)."""

    def __init__(self, scope: _Scope, names: _Names, fdef: ast.FunctionDef):
        self.s, self.names, self.fdef = scope, names, fdef
        self.loops: list[tuple[str, str]] = []      # (continue label, break label)
        self.depth = 0                              # >0: inside if/loop (not kernel top level)

    # ---- statements ----

    def body(self, stmts: list[ast.stmt]) -> None:
        for st in stmts:
            self.stmt(st)

    def stmt(self, node: ast.stmt) -> None:
        fn = getattr(self, f"visit_{type(node).__name__}", None)
        if fn is None:
            what = {"FunctionDef": "nested function definitions", "AsyncFunctionDef":
                    "nested function definitions", "Lambda": "lambdas"}.get(type(node).__name__)
            raise NotSupported(f"{what} are not supported" if what else
                               f"unsupported statement: {type(node).__name__}", node)
        fn(node)

    def visit_Assign(self, node: ast.Assign) -> None:
        if len(node.targets) != 1:
            raise NotSupported("multiple assignment targets", node)
        target = node.targets[0]
        if isinstance(target, ast.Subscript):
            self._store(target, *self._eval(node.value))
            return
        if not isinstance(target, ast.Name):
            raise NotSupported("assignment target must be a name or a[i]", node)
        if isinstance(node.value, ast.Call) and self.names.resolve(node.value.func) == "pf.shared_array":
            self._declare_shared(target, node.value, node)
            return
        val, kind = self._eval(node.value)
        dst = self.s.var_reg(target.id, kind, node)
        self._mov(dst, val, kind)

    def visit_AugAssign(self, node: ast.AugAssign) -> None:
        if isinstance(node.target, ast.Subscript):
            arr, addr = self._address(node.target)
            cur = self._load(arr, addr)
            res, kind = self._arith(node.op, (cur, arr.elem), node.value, node)
            self._store_at(arr, addr, res, kind, node.target)
            return
        if not isinstance(node.target, ast.Name):
            raise NotSupported("augmented assignment target must be a name or a[i]", node)
        cur = self.s.vars.get(node.target.id)
        if cur is None:
            raise NotSupported(f"{node.target.id!r} used before assignment", node)
        res, kind = self._arith(node.op, (cur, cur.kind), node.value, node, into=cur)
        if kind != cur.kind:
            raise NotSupported(f"variable {node.target.id!r} reassigned with a different type "
                               f"({cur.kind} -> {kind})", node)
        self._mov(cur, res, kind)

    def visit_If(self, node: ast.If) -> None:
        # Conditions are compiled straight into branches (and/or short-circuit, `not` flips
        # the polarity): no combined predicate is ever materialized, because our backend's
        # selector has no and.pred/or.pred/not.pred (openassembler.backend.ra.Selector).
        end_label = self.s.new_label("endif")
        else_label = self.s.new_label("else") if node.orelse else end_label
        self._jump(node.test, else_label, when=False)
        self.depth += 1
        self.body(node.body)
        if node.orelse:
            self.s.emit(f" bra {end_label};")
            self.s.emit(f"{else_label}:")
            self.body(node.orelse)
        self.depth -= 1
        self.s.emit(f"{end_label}:")

    def visit_While(self, node: ast.While) -> None:
        if node.orelse:
            raise NotSupported("'while ... else' is not supported", node.orelse[0])
        top, end = self.s.new_label("while"), self.s.new_label("wend")
        self.s.emit(f"{top}:")
        self._jump(node.test, end, when=False)
        self.loops.append((top, end))
        self.depth += 1
        self.body(node.body)
        self.depth -= 1
        self.loops.pop()
        self.s.emit(f" bra {top};")
        self.s.emit(f"{end}:")

    def visit_For(self, node: ast.For) -> None:
        # for v in range(start, stop[, step]) -- the only `for` form supported.
        if not (isinstance(node.target, ast.Name) and isinstance(node.iter, ast.Call)
                and self.names.resolve(node.iter.func) == "range" and not node.iter.keywords):
            raise NotSupported("only 'for i in range(...)' loops are supported", node)
        if node.orelse:
            raise NotSupported("'for ... else' is not supported", node.orelse[0])
        args = node.iter.args
        if len(args) == 1:
            start_e, stop_e, step = ast.Constant(value=0), args[0], 1
        elif len(args) in (2, 3):
            start_e, stop_e, step = args[0], args[1], 1
            if len(args) == 3:
                step = _const_value(args[2])
                if not isinstance(step, int):
                    raise NotSupported("range() step must be a constant int", node)
        else:
            raise NotSupported("range() takes 1-3 args", node)
        if step == 0:
            raise NotSupported("range() step must not be 0", node)
        if not _I32_MIN <= step <= _I32_MAX:
            raise NotSupported("range() step does not fit in i32", node)
        name = node.target.id

        # Python evaluates range()'s bounds once, then binds the variable on each iteration.
        start_v, start_k = self._eval(start_e)
        stop_v, stop_k = self._eval(stop_e)
        if start_k != "s32" or stop_k != "s32":
            raise NotSupported("range() bounds must be int32 expressions", node.iter)
        var = self.s.var_reg(name, "s32", node)
        # The variable doubles as the counter unless that would be observable: if the body
        # assigns it (Python: next iteration rebinds it anyway, the trip count is unchanged)
        # or it is read outside the loop (Python: it keeps the LAST value taken, not `stop`).
        inside = {id(n) for part in [node.target, *node.body] for n in ast.walk(part)}
        stored_in_body = any(isinstance(n, ast.Name) and n.id == name and isinstance(n.ctx, ast.Store)
                             for part in node.body for n in ast.walk(part))
        used_outside = any(isinstance(n, ast.Name) and n.id == name and id(n) not in inside
                           for n in ast.walk(self.fdef))
        ctr = self.s.new_reg("s32") if (stored_in_body or used_outside) else var
        self._mov(ctr, start_v, "s32")
        stop_reg = self.s.new_reg("s32")
        self.s.emit(f" mov.u32 {stop_reg.name}, {stop_v.name};")   # snapshot, never aliased

        top, cont, end = self.s.new_label("loop"), self.s.new_label("next"), self.s.new_label("loopend")
        self.s.emit(f"{top}:")
        pred = self.s.new_reg("pred")
        self.s.emit(f" setp.{'ge' if step > 0 else 'le'}.s32 {pred.name}, {ctr.name}, {stop_reg.name};")
        self.s.emit(f" @{pred.name} bra {end};")
        if ctr is not var:
            self.s.emit(f" mov.u32 {var.name}, {ctr.name};")
        self.loops.append((cont, end))
        self.depth += 1
        self.body(node.body)
        self.depth -= 1
        self.loops.pop()
        self.s.emit(f"{cont}:")
        if step > 0:
            self.s.emit(f" add.s32 {ctr.name}, {ctr.name}, {step};")
        else:
            self.s.emit(f" sub.s32 {ctr.name}, {ctr.name}, {-step};")
        self.s.emit(f" bra {top};")
        self.s.emit(f"{end}:")

    def visit_Break(self, node: ast.Break) -> None:
        if not self.loops:
            raise NotSupported("'break' outside a loop", node)
        self.s.emit(f" bra {self.loops[-1][1]};")

    def visit_Continue(self, node: ast.Continue) -> None:
        if not self.loops:
            raise NotSupported("'continue' outside a loop", node)
        self.s.emit(f" bra {self.loops[-1][0]};")

    def visit_Expr(self, node: ast.Expr) -> None:
        v = node.value
        if isinstance(v, ast.Constant) and isinstance(v.value, str):
            return                                   # docstring / bare string: no effect
        if isinstance(v, ast.Call) and self.names.resolve(v.func) == "pf.syncthreads":
            if v.args or v.keywords:
                raise NotSupported("syncthreads() takes no arguments", node)
            self.s.emit(" bar.sync 0;")
            return
        raise NotSupported("expression statement with no supported effect", node)

    def visit_Pass(self, node: ast.Pass) -> None:
        pass

    def visit_Return(self, node: ast.Return) -> None:
        if node.value is not None:
            raise NotSupported("kernels don't return a value (write to an output array)", node)
        # A bare `return` is the standard CUDA early-out (`if i >= n: return`).
        self.s.emit(f" bra {self.s.exit_label};")

    def _declare_shared(self, target: ast.Name, call: ast.Call, node: ast.AST) -> None:
        if self.depth or self.loops:
            raise NotSupported("shared_array() must be assigned at the kernel's top level, "
                               "not inside an if or a loop", node)
        name = target.id
        if name in self.s.arrays or name in self.s.vars:
            raise NotSupported(f"{name!r} is already defined; a shared_array needs its own name", node)
        if len(call.args) != 2 or call.keywords:
            raise NotSupported("shared_array(type, count) takes exactly two arguments", node)
        elem = _resolve_type(call.args[0], self.names)
        count = _const_value(call.args[1])
        if not isinstance(elem, Scalar):
            raise NotSupported("shared_array element type must be f32, i32 or u32", node)
        if not isinstance(count, int) or count <= 0:
            raise NotSupported("shared_array count must be a positive integer literal", node)
        self.s.smem_bytes += 4 * count
        if self.s.smem_bytes > _SMEM_LIMIT:
            raise NotSupported(f"shared_array total {self.s.smem_bytes} bytes exceeds the "
                               f"{_SMEM_LIMIT}-byte static shared-memory limit", node)
        sym = f"__smem_{name}"
        reg = self.s.new_reg("u32")
        self.s.emit(f" mov.u32 {reg.name}, {sym};")         # 32-bit shared-window address
        self.s.shared.append((sym, elem.ptx, count))
        self.s.arrays[name] = _Arr("shared", elem.ptx, reg, sym, count)

    def _jump(self, test: ast.expr, label: str, when: bool) -> None:
        """Branch to `label` iff bool(test) == when; otherwise fall through."""
        if isinstance(test, ast.UnaryOp) and isinstance(test.op, ast.Not):
            return self._jump(test.operand, label, not when)
        if isinstance(test, ast.BoolOp):
            if isinstance(test.op, ast.And) != when:
                # (and, jump if false) / (or, jump if true): the first deciding operand jumps
                for v in test.values:
                    self._jump(v, label, when)
            else:
                # (and, jump if true) / (or, jump if false): every operand is needed
                skip = self.s.new_label("sc")
                for v in test.values[:-1]:
                    self._jump(v, skip, not when)
                self._jump(test.values[-1], label, when)
                self.s.emit(f"{skip}:")
            return
        if isinstance(test, ast.Constant) and isinstance(test.value, (bool, int, float)):
            if bool(test.value) == when:
                self.s.emit(f" bra {label};")
            return
        if isinstance(test, ast.Compare):
            pred, inverted = self._compare(test, branch=True)
            when = when != inverted
        else:
            v, k = self._eval(test)
            if k == "pred":
                pred = v
            else:                              # Python truthiness: x != 0 (NaN is truthy)
                pred = self.s.new_reg("pred")
                zero = "0f00000000" if k == "f32" else "0"
                self.s.emit(f" setp.eq.{k} {pred.name}, {v.name}, {zero};")
                when = not when
        self.s.emit(f" @{'' if when else '!'}{pred.name} bra {label};")

    def _mov(self, dst: _Reg, src: _Reg, kind: str) -> None:
        if dst.name == src.name:
            return
        op = {"f32": "mov.f32", "pred": "mov.pred"}.get(kind, "mov.u32")
        self.s.emit(f" {op} {dst.name}, {src.name};")

    # ---- expressions ----

    def _ev(self, x) -> tuple[_Reg, str]:
        return x if isinstance(x, tuple) else self._eval(x)

    def _eval(self, node: ast.expr) -> tuple[_Reg, str]:
        cv = _const_value(node)
        if cv is not None:
            return self._lit_as(cv, "f32" if isinstance(cv, float) else "s32", node)
        if isinstance(node, ast.Name):
            if node.id in self.s.arrays:
                raise NotSupported(f"array {node.id!r} used as a value (index it: {node.id}[i])", node)
            if node.id not in self.s.vars:
                raise NotSupported(f"{node.id!r} used before assignment", node)
            r = self.s.vars[node.id]
            return r, r.kind
        if isinstance(node, ast.BinOp):
            return self._arith(node.op, node.left, node.right, node)
        if isinstance(node, ast.Compare):
            pred, _ = self._compare(node, branch=False)
            return pred, "pred"
        if isinstance(node, ast.BoolOp):
            raise NotSupported("'and'/'or' are only supported directly in an if/while condition "
                               "(e.g. 'if a < b and c < d:'), not assigned to a variable or nested "
                               "in another expression", node)
        if isinstance(node, ast.UnaryOp):
            return self._unaryop(node)
        if isinstance(node, ast.Call):
            return self._call(node)
        if isinstance(node, ast.Subscript):
            arr, addr = self._address(node)
            return self._load(arr, addr), arr.elem
        if isinstance(node, ast.Constant) and isinstance(node.value, bool):
            raise NotSupported("bool constants are only supported as a whole if/while condition "
                               "('while True:')", node)
        raise NotSupported(f"unsupported expression: {type(node).__name__}", node)

    def _lit_as(self, v, want: str, node: ast.AST) -> tuple[_Reg, str]:
        """Materialize literal v. An int literal next to an f32 operand becomes an f32
        constant (Python would promote it), but only when that conversion is exact."""
        if isinstance(v, int):
            if want == "f32":
                if _f32_bits(float(v)) != _f32_bits(float(_f32(float(v)))) or _f32(float(v)) != v:
                    raise NotSupported(f"int literal {v} is not exactly representable as f32", node)
                v = float(v)
            elif want == "u32":
                if not 0 <= v < (1 << 32):
                    raise NotSupported(f"literal {v} does not fit in u32", node)
                r = self.s.new_reg("u32")
                self.s.emit(f" mov.u32 {r.name}, {v};")
                return r, "u32"
            else:
                if not _I32_MIN <= v <= _I32_MAX:
                    raise NotSupported(f"int literal {v} does not fit in i32 (kernels compute in "
                                       "32-bit integers)", node)
                r = self.s.new_reg("s32")
                self.s.emit(f" mov.s32 {r.name}, {v};")
                return r, "s32"
        r = self.s.new_reg("f32")
        self.s.emit(f" mov.f32 {r.name}, 0f{_f32_bits(v):08X};")
        return r, "f32"

    def _pair(self, left, right, node):
        """Evaluate two operands; a literal takes the other side's type (see _lit_as)."""
        lit = lambda x: None if isinstance(x, tuple) else _const_value(x)  # noqa: E731
        lv, rv = lit(left), lit(right)
        if lv is not None and rv is not None:
            k = "f32" if isinstance(lv, float) or isinstance(rv, float) else "s32"
            return (*self._lit_as(lv, k, left), *self._lit_as(rv, k, right))
        if lv is not None:
            b, kb = self._ev(right)
            return (*self._lit_as(lv, kb, left), b, kb)
        a, ka = self._ev(left)
        if rv is not None:
            return (a, ka, *self._lit_as(rv, ka, right))
        return (a, ka, *self._ev(right))

    def _mixed(self, ka, kb, node):
        raise NotSupported(f"mixed-type operands ({ka} vs {kb}); convert explicitly with "
                           "float(x) or int(x)", node)

    def _arith(self, op: ast.operator, left, right, node: ast.AST,
               into: _Reg | None = None) -> tuple[_Reg, str]:
        """left/right: AST nodes or already-evaluated (reg, kind). `into`: write a one-
        instruction result straight there (`s += x` stays a single add, as before)."""
        if isinstance(op, ast.Div):
            return self._truediv(left, right, node)
        if isinstance(op, (ast.FloorDiv, ast.Mod)):
            return self._floordiv(op, left, right, node)
        mnem = {ast.Add: "add", ast.Sub: "sub", ast.Mult: "mul"}.get(type(op))
        if mnem is None:
            raise NotSupported(f"operator {type(op).__name__} is not supported", node)
        a, ka, b, kb = self._pair(left, right, node)
        if ka != kb:
            self._mixed(ka, kb, node)
        if ka == "pred":
            raise NotSupported("arithmetic on a comparison result", node)
        dst = into if into is not None and into.kind == ka else self.s.new_reg(ka)
        if ka == "f32":
            self.s.emit(f" {mnem}.f32 {dst.name}, {a.name}, {b.name};")
        else:
            self.s.emit(f" {mnem}{'.lo' if mnem == 'mul' else ''}.s32 {dst.name}, {a.name}, {b.name};")
        return dst, ka

    def _to_f32(self, x, node) -> _Reg:
        v = None if isinstance(x, tuple) else _const_value(x)
        if v is not None:
            return self._lit_as(v, "f32", node)[0]
        r, k = self._ev(x)
        if k == "f32":
            return r
        if k not in ("s32", "u32"):
            raise NotSupported(f"can't convert {k} to f32", node)
        d = self.s.new_reg("f32")
        self.s.emit(f" cvt.rn.f32.{k} {d.name}, {r.name};")
        return d

    def _truediv(self, left, right, node) -> tuple[_Reg, str]:
        a = self._to_f32(left, node)
        rv = None if isinstance(right, tuple) else _const_value(right)
        dst = self.s.new_reg("f32")
        if rv is not None:
            c = _f32(float(rv))
            if c == 0:
                raise NotSupported("division by a zero literal (Python raises ZeroDivisionError)", node)
            m, e = math.frexp(abs(c))
            if m == 0.5 and -127 <= e - 1 <= 127:
                # x / 2**k == x * 2**-k exactly (same real number, same single rounding)
                self.s.emit(f" mul.f32 {dst.name}, {a.name}, 0f{_f32_bits(1.0 / c):08X};")
                return dst, "f32"
        b = self._to_f32(right, node)
        self.s.emit(f" div.rn.f32 {dst.name}, {a.name}, {b.name};")
        return dst, "f32"

    def _floordiv(self, op, left, right, node) -> tuple[_Reg, str]:
        is_mod = isinstance(op, ast.Mod)
        sym = "%" if is_mod else "//"
        rv = None if isinstance(right, tuple) else _const_value(right)
        if rv is not None and not isinstance(left, tuple) and _const_value(left) is None:
            a, ka = self._eval(left)                   # keep a constant divisor an immediate
            if ka == "f32" or isinstance(rv, float):
                self._float_floordiv(sym, node)
            if rv == 0:
                raise NotSupported(f"{sym} by a zero literal (Python raises ZeroDivisionError)", node)
            if ka == "u32" and rv < 0 or not _I32_MIN <= rv <= (_I32_MAX if ka == "s32" else (1 << 32) - 1):
                raise NotSupported(f"divisor {rv} does not fit the {ka} operand", node)
            if ka not in ("s32", "u32"):
                self._mixed(ka, "s32", node)
            return self._divconst(a, ka, rv, is_mod), ka
        a, ka, b, kb = self._pair(left, right, node)
        if "f32" in (ka, kb):
            self._float_floordiv(sym, node)
        if ka != kb or ka not in ("s32", "u32"):
            self._mixed(ka, kb, node)
        return self._divreg(a, ka, b, is_mod), ka

    @staticmethod
    def _float_floordiv(sym, node):
        raise NotSupported(f"'{sym}' on f32 is not supported: Python's float floor division and "
                           "modulo use an exact fmod with special sign/zero/inf rules (1 // 0.1 is "
                           "9.0 although 1 / 0.1 is 10.0) that no PTX instruction reproduces; use "
                           f"int operands, or int(x) {sym} int(y) if that is what you mean", node)

    def _divconst(self, a: _Reg, k: str, d: int, is_mod: bool) -> _Reg:
        """a // d or a % d for a literal d != 0, Python floor semantics."""
        e = self.s.emit
        new = lambda: self.s.new_reg(k)  # noqa: E731
        out = new()
        if k == "u32":                                # floor == truncation for unsigned
            if _is_pow2(d):
                sh = d.bit_length() - 1
                e(f" and.b32 {out.name}, {a.name}, {d - 1};" if is_mod else
                  f" shr.u32 {out.name}, {a.name}, {sh};")
            else:
                e(f" {'rem' if is_mod else 'div'}.u32 {out.name}, {a.name}, {d};")
            return out
        if d == 1 or d == -1:
            if is_mod:
                e(f" mov.s32 {out.name}, 0;")
            elif d == 1:
                e(f" mov.u32 {out.name}, {a.name};")
            else:
                e(f" neg.s32 {out.name}, {a.name};")    # -2**31 // -1 wraps (Python: 2**31)
            return out
        if _is_pow2(d):
            # two's-complement arithmetic shift IS floor division; the low bits ARE the
            # floor remainder (in [0, d)). No correction needed.
            e(f" and.b32 {out.name}, {a.name}, {d - 1};" if is_mod else
              f" shr.s32 {out.name}, {a.name}, {d.bit_length() - 1};")
            return out
        if d == _I32_MIN:                             # |d| not an i32: use the general path
            dr = new()
            e(f" mov.s32 {dr.name}, {d};")
            return self._divreg(a, k, dr, is_mod)
        q, p, r, m = new(), new(), new(), new()
        if d > 0:
            # trunc q, r = a - q*d (sign of a). Floor differs iff r < 0: then q -= 1, r += d.
            # m = r >> 31 is -1 exactly then, so q + m and r + (m & d) -- branch-free.
            e(f" div.s32 {q.name}, {a.name}, {d};")
            e(f" mul.lo.s32 {p.name}, {q.name}, {d};")
            e(f" sub.s32 {r.name}, {a.name}, {p.name};")
            e(f" shr.s32 {m.name}, {r.name}, 31;")
        else:
            # d < 0: divide by |d| (backend's divide-by-constant only takes positives) and
            # negate. Floor differs iff r > 0: m = (-r) >> 31 is -1 exactly then.
            t, nr = new(), new()
            e(f" div.s32 {t.name}, {a.name}, {-d};")
            e(f" neg.s32 {q.name}, {t.name};")
            e(f" mul.lo.s32 {p.name}, {t.name}, {-d};")
            e(f" sub.s32 {r.name}, {a.name}, {p.name};")
            e(f" neg.s32 {nr.name}, {r.name};")
            e(f" shr.s32 {m.name}, {nr.name}, 31;")
        if is_mod:
            md = new()
            e(f" and.b32 {md.name}, {m.name}, {d};")
            e(f" add.s32 {out.name}, {r.name}, {md.name};")
        else:
            e(f" add.s32 {out.name}, {q.name}, {m.name};")
        return out

    def _divreg(self, a: _Reg, k: str, b: _Reg, is_mod: bool) -> _Reg:
        """a // b or a % b, b a register: truncating div + branch-free floor correction."""
        e = self.s.emit
        new = lambda: self.s.new_reg(k)  # noqa: E731
        out = new()
        if k == "u32":
            e(f" {'rem' if is_mod else 'div'}.u32 {out.name}, {a.name}, {b.name};")
            return out
        q, p, r, x, nr, nz, sg, m = (new() for _ in range(8))
        e(f" div.s32 {q.name}, {a.name}, {b.name};")
        e(f" mul.lo.s32 {p.name}, {q.name}, {b.name};")
        e(f" sub.s32 {r.name}, {a.name}, {p.name};")             # trunc remainder, sign of a
        # floor != trunc iff r != 0 and sign(r) != sign(b):  bit 31 of (r ^ b) & (r | -r)
        e(f" xor.b32 {x.name}, {r.name}, {b.name};")
        e(f" neg.s32 {nr.name}, {r.name};")
        e(f" or.b32 {nz.name}, {r.name}, {nr.name};")
        e(f" and.b32 {sg.name}, {x.name}, {nz.name};")
        e(f" shr.s32 {m.name}, {sg.name}, 31;")                  # -1 if correction, else 0
        if is_mod:
            md = new()
            e(f" and.b32 {md.name}, {m.name}, {b.name};")
            e(f" add.s32 {out.name}, {r.name}, {md.name};")
        else:
            e(f" add.s32 {out.name}, {q.name}, {m.name};")
        return out

    def _compare(self, node: ast.Compare, branch: bool) -> tuple[_Reg, bool]:
        """Returns (pred, inverted): pred == (comparison) xor inverted. In a branch, f32 !=
        is emitted as eq + inverted polarity (our backend has no setp.neu); as a value it
        must be setp.neu.f32 -- ordered ne would be wrong (false) on NaN."""
        if len(node.ops) != 1 or len(node.comparators) != 1:
            raise NotSupported("chained comparisons (a < b < c) are not supported", node)
        a, ka, b, kb = self._pair(node.left, node.comparators[0], node)
        if ka != kb:
            raise NotSupported(f"comparing mismatched types ({ka} vs {kb})", node)
        if ka == "pred":
            raise NotSupported("comparing comparison results", node)
        op = type(node.ops[0])
        cmp = {ast.Lt: "lt", ast.LtE: "le", ast.Gt: "gt", ast.GtE: "ge", ast.Eq: "eq",
               ast.NotEq: "ne"}.get(op)
        if cmp is None:
            raise NotSupported(f"comparison {op.__name__} not supported", node)
        inverted = False
        if ka == "f32" and cmp == "ne":
            cmp, inverted = ("eq", True) if branch else ("neu", False)
        dst = self.s.new_reg("pred")
        self.s.emit(f" setp.{cmp}.{ka} {dst.name}, {a.name}, {b.name};")
        return dst, inverted

    def _unaryop(self, node: ast.UnaryOp) -> tuple[_Reg, str]:
        if isinstance(node.op, ast.Not):
            raise NotSupported("'not' is only supported in an if/while condition (it is "
                               "compiled into the branch); write the inverse comparison instead", node)
        if isinstance(node.op, ast.UAdd):
            return self._eval(node.operand)
        if not isinstance(node.op, ast.USub):
            raise NotSupported(f"unary operator {type(node.op).__name__} not supported", node)
        v, k = self._eval(node.operand)
        if k not in ("f32", "s32"):
            raise NotSupported(f"unary - on {k}", node)
        dst = self.s.new_reg(k)
        self.s.emit(f" neg.{k} {dst.name}, {v.name};")
        return dst, k

    def _call(self, node: ast.Call) -> tuple[_Reg, str]:
        fname = self.names.resolve(node.func)
        if fname is None:
            raise NotSupported(f"call to {ast.unparse(node.func)!r} is not supported", node)
        if node.keywords:
            raise NotSupported(f"{fname}() keyword arguments are not supported", node)
        args, short = node.args, fname.split(".")[-1]
        if fname.startswith("pf.") and short in _SREGS:
            if args:
                raise NotSupported(f"{short}() takes no arguments", node)
            r = self.s.new_reg("s32")
            self.s.emit(f" mov.u32 {r.name}, {_SREGS[short]};")
            return r, "s32"
        if fname in ("min", "max"):
            if len(args) < 2:
                raise NotSupported(f"{fname}() needs at least two arguments (no iterables)", node)
            # no side effects in this subset, so evaluating non-literals first is safe; a
            # literal takes the type of the first non-literal argument (as in _pair)
            ev = {i: self._eval(x) for i, x in enumerate(args) if _const_value(x) is None}
            lits = [_const_value(x) for x in args if _const_value(x) is not None]
            k = (next(iter(ev.values()))[1] if ev else
                 "f32" if any(isinstance(v, float) for v in lits) else "s32")
            vals = [ev[i] if i in ev else self._lit_as(_const_value(x), k, x)
                    for i, x in enumerate(args)]
            cur, k = vals[0]
            for b, kb in vals[1:]:                   # CPython folds left to right
                cur = self._minmax(fname, cur, k, b, kb, node)
            return cur, k
        if fname in ("abs", "float", "int") or fname.startswith(("pf.", "math.")) and short in _MATH1:
            if len(args) != 1:
                raise NotSupported(f"{short}() takes exactly one argument", node)
        if fname == "abs":
            v, k = self._eval(args[0])
            if k == "u32":
                return v, k
            dst = self.s.new_reg(k)
            if k == "f32":
                self.s.emit(f" abs.f32 {dst.name}, {v.name};")
            elif k == "s32":       # max(x, -x): abs.s32 exactly, incl. wrapping at -2**31
                n = self.s.new_reg("s32")
                self.s.emit(f" neg.s32 {n.name}, {v.name};")
                self.s.emit(f" max.s32 {dst.name}, {v.name}, {n.name};")
            else:
                raise NotSupported(f"abs() of {k}", node)
            return dst, k
        if fname == "float":
            cv = _const_value(args[0])
            return (self._lit_as(float(cv), "f32", node) if cv is not None
                    else (self._to_f32(args[0], node), "f32"))
        if fname == "int":
            cv = _const_value(args[0])
            if cv is not None:
                return self._lit_as(int(cv), "s32", node)
            v, k = self._eval(args[0])
            if k == "s32":
                return v, k
            if k != "f32":
                raise NotSupported(f"int() of {k} is not supported (u32 values >= 2**31 don't "
                                   "fit in i32)", node)
            dst = self.s.new_reg("s32")
            self.s.emit(f" cvt.rzi.s32.f32 {dst.name}, {v.name};")    # truncation, like int()
            return dst, "s32"
        if short in _MATH1 and (fname.startswith("pf.") or fname.startswith("math.")):
            return self._math(short, args[0], node), "f32"
        if fname == "pf.syncthreads":
            raise NotSupported("syncthreads() is a statement, not a value", node)
        if fname == "pf.shared_array":
            raise NotSupported("shared_array() must be assigned directly to a name at the "
                               "kernel's top level: s = shared_array(f32, 256)", node)
        raise NotSupported(f"call to {ast.unparse(node.func)!r} is not supported", node)

    def _minmax(self, fname, a, ka, b, kb, node) -> _Reg:
        if ka != kb:
            raise NotSupported(f"{fname}() of mixed types ({ka} vs {kb})", node)
        dst = self.s.new_reg(ka)
        if ka in ("s32", "u32"):
            self.s.emit(f" {fname}.{ka} {dst.name}, {a.name}, {b.name};")
        elif ka == "f32":
            # CPython: min(a, b) is `b if b < a else a` (max: b > a). PTX min.f32 would
            # return the non-NaN operand and order -0 < +0 -- both differ from Python.
            p = self.s.new_reg("pred")
            self.s.emit(f" setp.{'lt' if fname == 'min' else 'gt'}.f32 {p.name}, {b.name}, {a.name};")
            self.s.emit(f" selp.f32 {dst.name}, {b.name}, {a.name}, {p.name};")
        else:
            raise NotSupported(f"{fname}() of {ka}", node)
        return dst

    def _math(self, fn: str, arg, node) -> _Reg:
        x = self._to_f32(arg, node)
        dst = self.s.new_reg("f32")
        e = self.s.emit
        if fn == "sqrt":
            e(f" sqrt.rn.f32 {dst.name}, {x.name};")
        elif fn == "rsqrt":
            e(f" rsqrt.approx.f32 {dst.name}, {x.name};")
        elif fn == "exp":
            t = self.s.new_reg("f32")
            e(f" mul.f32 {t.name}, {x.name}, 0f{_LOG2E_F32:08X};")
            e(f" ex2.approx.f32 {dst.name}, {t.name};")
        elif fn == "log":
            t = self.s.new_reg("f32")
            e(f" lg2.approx.f32 {t.name}, {x.name};")
            e(f" mul.f32 {dst.name}, {t.name}, 0f{_LN2_F32:08X};")
        elif fn == "tanh":
            if _sm(self.s.arch) < 75:
                raise NotSupported(f"tanh() needs tanh.approx.f32 (sm_75+), target is {self.s.arch}", node)
            e(f" tanh.approx.f32 {dst.name}, {x.name};")
        return dst

    # ---- memory ----

    def _address(self, sub: ast.Subscript) -> tuple[_Arr, str]:
        """PTX address operand for arr[i] (with the address arithmetic emitted)."""
        if not isinstance(sub.value, ast.Name) or sub.value.id not in self.s.arrays:
            raise NotSupported("subscript target must be a declared array", sub)
        arr = self.s.arrays[sub.value.id]
        ci = _const_value(sub.slice)
        if isinstance(ci, int):
            if ci < 0:
                raise NotSupported("negative index: GPU arrays don't count from the end "
                                   "like Python lists", sub)
            if arr.length is not None and ci >= arr.length:
                raise NotSupported(f"index {ci} out of range for shared_array of {arr.length}", sub)
            if 4 * ci < (1 << 23):                    # fits the 24-bit signed address offset
                return arr, (f"[{arr.sym}+{4 * ci}]" if arr.space == "shared"
                             else f"[{arr.base.name}+{4 * ci}]")
        idx, idx_kind = self._eval(sub.slice)
        if idx_kind != "s32":
            raise NotSupported(f"array index must be an int32 expression, not {idx_kind}", sub)
        if arr.space == "shared":
            off, addr = self.s.new_reg("u32"), self.s.new_reg("u32")
            self.s.emit(f" shl.b32 {off.name}, {idx.name}, 2;")
            self.s.emit(f" add.s32 {addr.name}, {off.name}, {arr.base.name};")
            return arr, f"[{addr.name}]"
        addr = self.s.new_reg("ptr")
        # mul.wide.u32 (not .s32): our backend fuses mul.wide+add.s64 of a cbank-held
        # pointer into one IMAD.WIDE, and the encoder only has a template for the unsigned
        # form of that fusion (see openassembler/isa/encode.py). Negative indices are out
        # of bounds anyway (see the module docstring).
        self.s.emit(f" mul.wide.u32 {addr.name}, {idx.name}, 4;")
        self.s.emit(f" add.s64 {addr.name}, {arr.base.name}, {addr.name};")
        return arr, f"[{addr.name}]"

    def _load(self, arr: _Arr, addr: str) -> _Reg:
        dst = self.s.new_reg(arr.elem)
        self.s.emit(f" ld.{arr.space}.{'f32' if arr.elem == 'f32' else 'u32'} {dst.name}, {addr};")
        return dst

    def _store(self, target: ast.Subscript, val: _Reg, kind: str) -> None:
        arr, addr = self._address(target)
        self._store_at(arr, addr, val, kind, target)

    def _store_at(self, arr: _Arr, addr: str, val: _Reg, kind: str, node) -> None:
        if kind != arr.elem:
            # `out[i] = 1` into an Array(f32) would store the integer's raw bits (1.4e-45,
            # not 1.0) and --verify can't see it: interpreter and SASS agree on the wrong value.
            raise NotSupported(f"storing a {kind} value into an Array of {arr.elem} "
                               "(write 1.0, not 1, for a float array; or convert with float()/int())", node)
        self.s.emit(f" st.{arr.space}.{'f32' if arr.elem == 'f32' else 'u32'} {addr}, {val.name};")


# ---- entry points ----------------------------------------------------------------------------

def _f32(v: float) -> float:
    try:
        return struct.unpack("<f", struct.pack("<f", v))[0]
    except OverflowError:
        return math.copysign(math.inf, v)


def _sm(arch: str) -> int:
    digits = "".join(ch for ch in arch.split("_", 1)[-1] if ch.isdigit())
    return int(digits) if digits else 0


def _ident(name: str, what: str, node: ast.AST) -> str:
    if not (name.isascii() and name.isidentifier()) or name.startswith("__smem_"):
        raise NotSupported(f"{what} name {name!r} is not a valid PTX identifier (ASCII only, "
                           "no __smem_ prefix)", node)
    return name


def _compile_entry(fdef: ast.FunctionDef, names: _Names, arch: str) -> str:
    """One `.visible .entry` (no module header) for a kernel FunctionDef."""
    if isinstance(fdef, ast.AsyncFunctionDef):
        raise NotSupported("async kernels are not supported", fdef)
    a = fdef.args
    if a.vararg or a.kwarg or a.kwonlyargs or a.posonlyargs:
        raise NotSupported("kernel parameters must be plain positional parameters "
                           "(no *args, **kwargs, keyword-only or positional-only)", fdef)
    if a.defaults:
        raise NotSupported("kernel parameters can't have default values", fdef)
    _ident(fdef.name, "kernel", fdef)
    scope = _Scope(arch=arch)
    for arg in a.args:
        if arg.annotation is None:
            raise NotSupported(f"parameter {arg.arg!r} has no type annotation", fdef)
        t = _resolve_type(arg.annotation, names)
        _ident(arg.arg, "parameter", arg)
        if isinstance(t, ArrayType):
            scope.params.append(("u64", arg.arg))
            scope.arrays[arg.arg] = _Arr("global", t.elem.ptx, scope.new_reg("ptr"))
        else:
            scope.params.append((t.ptx, arg.arg))
            scope.vars[arg.arg] = scope.new_reg(t.ptx)
    _BarrierCheck(fdef, names).run()
    _Emitter(scope, names, fdef).body(fdef.body)
    return _render(fdef.name, scope)


def _render(name: str, s: _Scope) -> str:
    param_list = ", ".join(f".param .{t} {n}" for t, n in s.params)
    out = [f".visible .entry {name}({param_list})\n{{"]
    for sym, ty, count in s.shared:
        out.append(f" .shared .align 4 .{'f32' if ty == 'f32' else 'b32'} {sym}[{count}];")
    if s.n_p:
        out.append(f" .reg .pred %p<{s.n_p + 1}>;")
    if s.n_r:
        out.append(f" .reg .b32 %r<{s.n_r + 1}>;")
    if s.n_f:
        out.append(f" .reg .f32 %f<{s.n_f + 1}>;")
    if s.n_rd:
        out.append(f" .reg .b64 %rd<{s.n_rd + 1}>;")
    for ptx_t, pname in s.params:
        if ptx_t == "u64":
            r = s.arrays[pname].base
            out.append(f" ld.param.u64 {r.name}, [{pname}];")
            out.append(f" cvta.to.global.u64 {r.name}, {r.name};")
        else:
            r = s.vars[pname]
            out.append(f" ld.param.{'f32' if ptx_t == 'f32' else 'u32'} {r.name}, [{pname}];")
    out.extend(s.lines)
    out.append(f"{s.exit_label}:")
    out.append(" ret;\n}")
    return "\n".join(out) + "\n"


def _parse_file(path: Path) -> ast.Module:
    try:
        src = Path(path).read_text(encoding="utf-8")
    except UnicodeDecodeError as e:
        raise NotSupported(f"{path} is not valid UTF-8: {e}", path=str(path)) from e
    try:
        return ast.parse(src, filename=str(path))
    except SyntaxError as e:
        raise NotSupported(f"syntax error in {path}:{e.lineno}: {e.msg}", path=str(path),
                           lineno=e.lineno) from e
    except ValueError as e:                     # e.g. NUL bytes in the source
        raise NotSupported(f"can't parse {path}: {e}", path=str(path)) from e


def _is_kernel_decorator(d: ast.expr, names: _Names) -> bool:
    if isinstance(d, ast.Call) and names.resolve(d.func) == "pf.kernel":
        raise NotSupported("@kernel takes no arguments (write @kernel, not @kernel())", d)
    return names.resolve(d) == "pf.kernel"


def _file_kernels(tree: ast.Module, names: _Names, path) -> list[ast.FunctionDef]:
    """Top-level @kernel functions, in file order; duplicate names are an error (Python
    would silently keep the last one)."""
    found: dict[str, ast.FunctionDef] = {}
    out = []
    for n in tree.body:
        if isinstance(n, (ast.FunctionDef, ast.AsyncFunctionDef)) \
                and any(_is_kernel_decorator(d, names) for d in n.decorator_list):
            if len(n.decorator_list) != 1:
                raise NotSupported(f"kernel {n.name!r} has other decorators besides @kernel", n)
            if n.name in found:
                raise NotSupported(f"duplicate @kernel name {n.name!r} (first defined on line "
                                   f"{found[n.name].lineno})", n)
            found[n.name] = n
            out.append(n)
    return out


def compile_file(path: Path, arch: str = "sm_80") -> tuple[str, list[str]]:
    """Compile every top-level @kernel in `path` into ONE PTX module (one header, one
    .visible .entry per kernel, in file order) WITHOUT importing or executing the file.
    Returns (ptx, kernel names); ("", []) if the file has no @kernel. Errors are
    NotSupported naming the file and line."""
    path = Path(path)
    tree = _parse_file(path)
    names = _Names(tree)
    try:
        kernels = _file_kernels(tree, names, path)
        if not kernels:
            return "", []
        entries = [_compile_entry(k, names, arch) for k in kernels]
    except NotSupported as e:
        raise e.with_path(path) from None
    return HEADER.format(arch=arch) + "\n".join(entries), [k.name for k in kernels]


class KernelRef:
    """A @kernel found statically in a file by find_kernel (the file was never executed).
    Accepted by compile_kernel exactly like the decorated function."""

    _is_openassembler_kernel = True

    def __init__(self, path: Path, fdef: ast.FunctionDef, names: _Names):
        self.path, self.fdef, self.names = path, fdef, names
        self.__name__ = fdef.name

    def __repr__(self) -> str:
        return f"KernelRef({self.__name__!r} in {self.path}, line {self.fdef.lineno})"

    def __call__(self, *_a, **_kw):
        raise NotSupported(f"{self.__name__} is a @kernel found in {self.path}; compile it with "
                           "openassembler.pyfront.compile_kernel(...)")


def find_kernel(path, entry: str | None) -> KernelRef:
    """Find the @kernel named `entry` in a .py file (or the only one, if entry is None)
    WITHOUT importing it -- same static scan as compile_file. Raises NotSupported if none,
    or several when entry is None (same "don't guess" policy as the rest of pyfront)."""
    path = Path(path)
    tree = _parse_file(path)
    names = _Names(tree)
    try:
        kernels = {k.name: k for k in _file_kernels(tree, names, path)}
    except NotSupported as e:
        raise e.with_path(path) from None
    if entry:
        if entry not in kernels:
            raise NotSupported(f"no @kernel function named {entry!r} in {path}; have {list(kernels)}")
        fdef = kernels[entry]
    elif len(kernels) != 1:
        raise NotSupported(f"{path} has {len(kernels)} @kernel functions, pass --kernel NAME; "
                           f"have {list(kernels)}")
    else:
        (fdef,) = kernels.values()
    return KernelRef(path, fdef, names)


def _live_source(fn) -> tuple[ast.FunctionDef, _Names, str | None]:
    """AST of a live function: parse its WHOLE source file (so the names/imports it sees
    are exactly those compile_file would see) and pick the def by line; fall back to the
    function's own source text (e.g. defined in a REPL)."""
    path = inspect.getsourcefile(fn)
    first = fn.__code__.co_firstlineno
    if path and Path(path).is_file():
        try:
            tree = ast.parse(Path(path).read_text(encoding="utf-8"), filename=path)
        except (SyntaxError, ValueError, UnicodeDecodeError):
            tree = None
        if tree is not None:
            for n in ast.walk(tree):
                if isinstance(n, (ast.FunctionDef, ast.AsyncFunctionDef)) and n.name == fn.__name__ \
                        and first in {n.lineno, *(d.lineno for d in n.decorator_list)}:
                    return n, _Names(tree), path
    lines, first = inspect.getsourcelines(fn)
    mod = ast.parse(textwrap.dedent("".join(lines)))
    ast.increment_lineno(mod, first - 1)     # report real file line numbers, not "line 2"
    (fdef,) = [n for n in mod.body if isinstance(n, (ast.FunctionDef, ast.AsyncFunctionDef))]
    return fdef, _Names(mod), None


def compile_kernel(fn, arch: str = "sm_80") -> str:
    """PTX (header + one .visible .entry) for one kernel: a @kernel-decorated function, a
    plain function, or a find_kernel() result. Byte-identical to the corresponding entry
    of compile_file(). Raises NotSupported for anything outside the module docstring's
    subset."""
    if isinstance(fn, KernelRef):
        fdef, names, path = fn.fdef, fn.names, fn.path
    else:
        fdef, names, path = _live_source(getattr(fn, "__wrapped__", fn))
    try:
        return HEADER.format(arch=arch) + _compile_entry(fdef, names, arch)
    except NotSupported as e:
        raise (e.with_path(path) if path else e) from None


def kernel(fn):
    """Marks a function as pyfront-compilable. Calling it directly in plain Python raises --
    use openassembler.pyfront.compile_kernel(fn) to get PTX."""

    def _no_call(*_a, **_kw):
        raise NotSupported(f"{fn.__name__} is a @kernel function; call "
                           f"openassembler.pyfront.compile_kernel({fn.__name__}) to get PTX, "
                           "not the function itself")

    _no_call.__wrapped__ = fn
    _no_call.__name__ = fn.__name__
    _no_call.__qualname__ = getattr(fn, "__qualname__", fn.__name__)
    _no_call._is_openassembler_kernel = True
    return _no_call
