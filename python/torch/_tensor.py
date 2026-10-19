from __future__ import annotations

from dataclasses import dataclass, field
from typing import TYPE_CHECKING, Callable, Sequence

from ._runtime import _get_runtime, _run_js_awaitable

if TYPE_CHECKING:
    from .autograd import _Node


def _format_tensor_values(value: object) -> str:
    if isinstance(value, list):
        return "[" + ", ".join(_format_tensor_values(item) for item in value) + "]"
    if isinstance(value, bool):
        return "True" if value else "False"
    if isinstance(value, int):
        return str(value)
    if isinstance(value, float):
        return f"{value:.4f}"
    if isinstance(value, complex):
        sign = "+" if value.imag >= 0 else "-"
        return f"{value.real:.4f}{sign}{abs(value.imag):.4f}j"
    return repr(value)


def _pt_format(values, dtype: str, ndim: int) -> str:
    """ai2ai: PyTorch-style printing (aligned columns, one row per line, 4 decimals or sci)."""
    flat = []

    def walk(v):
        if isinstance(v, list):
            for u in v:
                walk(u)
        else:
            flat.append(v)
    walk(values)
    is_float = dtype.startswith("float") or dtype.startswith("bfloat")
    if dtype == "bool":
        fmt = lambda v: "True" if v else "False"
    elif not is_float:
        fmt = lambda v: str(int(v))
    else:
        import math
        fin = [abs(float(v)) for v in flat if math.isfinite(float(v))]
        nz = [v for v in fin if v != 0]
        wide = bool(nz) and (max(nz) / min(nz) > 1000 or max(nz) > 1e8)
        if fin and all(float(v).is_integer() for v in flat if math.isfinite(float(v))) and not wide:
            fmt = lambda v: (f"{float(v):.0f}." if math.isfinite(float(v)) else str(float(v)))
        elif nz and (max(nz) / min(nz) > 1000 or max(nz) > 1e8 or min(nz) < 1e-4):
            fmt = lambda v: f"{float(v):.4e}"
        else:
            fmt = lambda v: f"{float(v):.4f}"
    width = max((len(fmt(v)) for v in flat), default=0)
    if ndim == 0:
        return fmt(values)

    def rec(v, depth):
        if not isinstance(v, list) or not v or not isinstance(v[0], list):
            items = v if isinstance(v, list) else [v]
            return "[" + ", ".join(fmt(x).rjust(width) for x in items) + "]"
        sep = "," + "\n" * max(0, ndim - depth - 2) + "\n" + " " * (7 + depth + 1)
        return "[" + sep.join(rec(u, depth + 1) for u in v) + "]"
    return rec(values, 0)


class Size(tuple):
    """ai2ai: torch.Size, a tuple that prints like PyTorch's."""
    def __repr__(self) -> str:
        return f"torch.Size({list(self)})"

    __str__ = __repr__

    def numel(self) -> int:
        n = 1
        for d in self:
            n *= d
        return n


def _ai2ai_matmul(a, b, native):
    """ai2ai: PyTorch matmul semantics (1-d, broadcast batch dims) on top of the runtime's
    2-d and equal-batch 3-d kernels, which are the only cases it gets right."""
    if len(a._shape) == 1:
        return _ai2ai_matmul(a.unsqueeze(0), b, native).squeeze(-2)
    if len(b._shape) == 1:
        return _ai2ai_matmul(a, b.unsqueeze(-1), native).squeeze(-1)
    if len(a._shape) == 2 and len(b._shape) == 2:
        return native(a, b)
    n, k = a._shape[-2], a._shape[-1]
    m = b._shape[-1]
    if len(b._shape) == 2:
        return native(a.reshape(-1, k), b).reshape(*a._shape[:-1], m)
    ba, bb = list(a._shape[:-2]), list(b._shape[:-2])
    nd = max(len(ba), len(bb))
    ba, bb = [1] * (nd - len(ba)) + ba, [1] * (nd - len(bb)) + bb
    batch = []
    for x, y in zip(ba, bb):
        if x != y and 1 not in (x, y):
            raise RuntimeError(f"matmul: batch dims {a._shape[:-2]} and {b._shape[:-2]} do not broadcast")
        batch.append(max(x, y))
    a3 = a.reshape(*ba, n, k).expand(*batch, n, k).reshape(-1, n, k)
    b3 = b.reshape(*bb, k, m).expand(*batch, k, m).reshape(-1, k, m)
    return native(a3, b3).reshape(*batch, n, m)


class _CallableInt(int):
    """An int that also works as numel()."""
    def __call__(self) -> int:
        return int(self)


@dataclass(slots=True)
class Tensor:
    _id: int
    _shape: list[int]
    _dtype: str
    _requires_grad: bool = False
    _node: "_Node | None" = field(default=None, repr=False)
    _backward_hooks: dict[int, Callable] = field(default_factory=dict, repr=False)
    grad: "Tensor | None" = field(default=None, repr=False)
    _retains_grad: bool = field(default=False, repr=False)

    @property
    def shape(self) -> tuple[int, ...]:
        return Size(self._shape)

    @property
    def dtype(self) -> str:
        from . import dtype as _dtype_cls  # ai2ai: prints as torch.float32
        return _dtype_cls(self._dtype.encode().decode() if isinstance(self._dtype, str) else self._dtype)

    @property
    def device(self) -> str:
        return "cpu"

    @property
    def ndim(self) -> int:
        return len(self._shape)

    @property
    def numel(self) -> int:
        # ai2ai: PyTorch's numel is a method; return an int that can also be called
        n = _CallableInt(1)
        for s in self._shape:
            n *= s
        n = _CallableInt(n)
        return n

    @property
    def requires_grad(self) -> bool:
        return self._requires_grad

    @requires_grad.setter
    def requires_grad(self, value: bool) -> None:
        self._requires_grad = value

    def requires_grad_(self, requires_grad_: bool = True) -> "Tensor":
        self._requires_grad = requires_grad_
        return self

    @property
    def is_leaf(self) -> bool:
        return self._node is None

    def register_hook(self, hook: Callable[["Tensor"], "Tensor | None"]) -> int:
        hook_id = id(hook)
        self._backward_hooks[hook_id] = hook
        return hook_id

    def remove_hook(self, hook_id: int) -> None:
        self._backward_hooks.pop(hook_id, None)

    def retain_grad(self) -> None:
        self._retains_grad = True

    def backward(
        self,
        gradient: "Tensor | None" = None,
        retain_graph: bool = False,
        create_graph: bool = False,
        inputs: Sequence["Tensor"] | None = None,
    ) -> None:
        from .autograd import _backward_from_tensor
        _backward_from_tensor(self, gradient, retain_graph, create_graph)

    def to(self, dtype: str, device: object = None) -> "Tensor":
        if dtype is not None:
            dtype = str(dtype).replace("torch.", "")
        rt_cast = None
        if dtype is not None and dtype != self._dtype:
            from ._runtime import _get_runtime
            rt_cast = getattr(_get_runtime(), "cast", None) if getattr(_get_runtime(), "backend", None) == "cpu" else None
        if rt_cast is not None:  # ai2ai: real cast on the cpu backend (truncates floats -> ints)
            from .tensor_ops import _js_meta_to_tuple
            tid, shp, dt = _js_meta_to_tuple(rt_cast(self._id, dtype))
            out = Tensor(tid, shp, dt, _requires_grad=self._requires_grad and dt.startswith("float"))
            if out._requires_grad:
                from .autograd import _Node
                out._node = _Node(out, lambda g, src=self: (g.to(src._dtype),), [self])
            return out
        if dtype is not None and dtype != self._dtype:
            from .tensor_factories_ops import zeros_like_from_tensor
            from .tensor_ops import add_from_tensors
            empty = zeros_like_from_tensor(self, dtype)
            return add_from_tensors(empty, self)
        return self

    def clone(self) -> "Tensor":
        return self.add(0.0)

    def detach(self) -> "Tensor":
        t = Tensor(self._id, list(self._shape), self._dtype)
        return t

    def detach_(self) -> "Tensor":
        self._node = None
        self.grad = None
        return self

    def contiguous(self) -> "Tensor":
        return self

    cpu = detach
    cuda = detach

    def half(self) -> "Tensor":
        return Tensor(self._id, self._shape, "float16", _requires_grad=self._requires_grad)

    def bfloat16(self) -> "Tensor":
        return Tensor(self._id, self._shape, "bfloat16", _requires_grad=self._requires_grad)

    def float(self) -> "Tensor":
        return self if self._dtype == "float32" else self.to("float32")

    def double(self) -> "Tensor":
        return self.to("float64") if self._dtype != "float64" else self

    def long(self) -> "Tensor":
        return self.to("int64")

    def int(self) -> "Tensor":
        return self.to("int32")

    def byte(self) -> "Tensor":
        return self.to("uint8")

    def bool(self) -> "Tensor":
        return self.to("bool")

    def __bool__(self) -> bool:
        return self.item() != 0

    def __int__(self) -> int:
        return int(self.item())

    def __float__(self) -> float:
        return float(self.item())

    def __index__(self) -> int:
        return int(self.item())

    def __repr__(self) -> str:
        try:
            values = self.tolist()
        except Exception:
            return (
                f"Tensor(_id={self._id}, _shape={self._shape}, "
                f"_dtype='{self._dtype}', _requires_grad={self._requires_grad})"
            )
        suffix = ""
        if self._dtype not in ("float32", "int64", "bool"):
            suffix += f", dtype=torch.{self._dtype.encode().decode()}"
        if self._requires_grad:
            suffix += ", grad_fn=<Backward>" if self._node is not None else ", requires_grad=True"
        return "tensor(" + _pt_format(values, self._dtype, len(self._shape)) + suffix + ")"

    __str__ = __repr__

    def __len__(self) -> int:
        return self._shape[0] if self._shape else 0

    def zero_(self) -> "Tensor":
        return self.fill_(0.0)

    def fill_(self, value: float) -> "Tensor":
        import torch
        self._set(torch.full(list(self._shape), float(value), dtype=self._dtype))
        return self

    def copy_(self, src: "Tensor") -> "Tensor":
        import torch
        if not isinstance(src, Tensor):
            src = torch.tensor(src, dtype=self._dtype)
        new = (torch.zeros(list(self._shape), dtype=self._dtype) + src.detach()).detach()
        self._set(new)
        return self

    @property
    def data(self) -> "Tensor":
        return self

    @data.setter
    def data(self, value: "Tensor") -> None:
        self.copy_(value)

    def __matmul__(self, other: "Tensor") -> "Tensor":
        import torch
        return self.matmul(other if isinstance(other, Tensor) else torch.tensor(other))

    def __rmatmul__(self, other: object) -> "Tensor":
        import torch
        return torch.tensor(other).matmul(self)

    def __imatmul__(self, other: "Tensor") -> "Tensor":
        return self.__matmul__(other)

    def t(self) -> "Tensor":
        return self.T

    def narrow(self, dim: int, start: int, length: int) -> "Tensor":
        return self.slice(dim=dim, start=start, end=start + length)

    def repeat(self, *sizes: int) -> "Tensor":
        from ._tensor_runtime_bridge import repeat_from_tensor
        return repeat_from_tensor(self, list(sizes))

    def repeat_interleave(self, repeats: int, dim: int | None = None) -> "Tensor":
        from ._tensor_math_helpers import repeat_interleave_from_tensor
        return repeat_interleave_from_tensor(self, repeats, dim)

    tile = repeat

    def topk(self, k: int, dim: int = -1, largest: bool = True) -> tuple["Tensor", "Tensor"]:
        from .tensor_ops import topk_from_tensor
        return topk_from_tensor(self, k, dim, largest)

    def sort(self, dim: int = -1, descending: bool = False) -> tuple["Tensor", "Tensor"]:
        from .tensor_ops import sort_from_tensor
        return sort_from_tensor(self, dim, descending)

    def gather(self, dim: int, index: "Tensor") -> "Tensor":
        from .tensor_ops import gather_from_tensor
        return gather_from_tensor(self, dim, index)

    def scatter_(self, dim: int, index: "Tensor", src: "Tensor | float") -> "Tensor":
        from .tensor_ops import scatter_from_tensor
        return scatter_from_tensor(self, dim, index, src)

    def argsort(self, dim: int = -1, descending: bool = False) -> "Tensor":
        from .tensor_ops import sort_from_tensor
        _, indices = sort_from_tensor(self, dim, descending)
        return indices

    def __add__(self, other: "Tensor | float") -> "Tensor":
        return self.add(other)

    def __radd__(self, other: "Tensor | float") -> "Tensor":
        from ._tensor_math_helpers import radd_from_tensor
        return radd_from_tensor(self, other)

    def __mul__(self, other: "Tensor | float") -> "Tensor":
        return self.mul(other)

    def __rmul__(self, other: "Tensor | float") -> "Tensor":
        return self.mul(other)

    def __sub__(self, other: "Tensor | float") -> "Tensor":
        return self.sub(other)

    def __rsub__(self, other: "Tensor | float") -> "Tensor":
        from ._tensor_math_helpers import rsub_from_tensor
        return rsub_from_tensor(self, other)

    def __truediv__(self, other: "Tensor | float") -> "Tensor":
        return self.div(other)

    def __rtruediv__(self, other: "Tensor | float") -> "Tensor":  # ai2ai
        return self.reciprocal().mul(other) if not isinstance(other, Tensor) else other.div(self)

    def __rpow__(self, other: "Tensor | float") -> "Tensor":  # ai2ai: c ** x = exp(x ln c)
        import math
        if isinstance(other, Tensor):
            return other.pow(self)
        return self.mul(math.log(float(other))).exp()

    def __neg__(self) -> "Tensor":
        return self.neg()

    def __lt__(self, other: "Tensor | float | int | bool") -> "Tensor":
        from .tensor_ops import lt_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(other, (float, int, bool)):
            other = _scalar_to_tensor(other, _sdt(other, self._dtype))
        return lt_from_tensors(self, other)

    def __le__(self, other: "Tensor | float | int | bool") -> "Tensor":
        from .tensor_ops import le_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(other, (float, int, bool)):
            other = _scalar_to_tensor(other, _sdt(other, self._dtype))
        return le_from_tensors(self, other)

    def __gt__(self, other: "Tensor | float | int | bool") -> "Tensor":
        from .tensor_ops import gt_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(other, (float, int, bool)):
            other = _scalar_to_tensor(other, _sdt(other, self._dtype))
        return gt_from_tensors(self, other)

    def __ge__(self, other: "Tensor | float | int | bool") -> "Tensor":
        from .tensor_ops import ge_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(other, (float, int, bool)):
            other = _scalar_to_tensor(other, _sdt(other, self._dtype))
        return ge_from_tensors(self, other)

    def __eq__(self, other: "Tensor | float | int | bool") -> "Tensor":
        from .tensor_ops import eq_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(other, (float, int, bool)):
            other = _scalar_to_tensor(other, _sdt(other, self._dtype))
        return eq_from_tensors(self, other)

    def __ne__(self, other: "Tensor | float | int | bool") -> "Tensor":
        from .tensor_ops import ne_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(other, (float, int, bool)):
            other = _scalar_to_tensor(other, _sdt(other, self._dtype))
        return ne_from_tensors(self, other)

    def __pow__(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import pow_from_tensors, _scalar_to_tensor, _sdt
        return pow_from_tensors(self, other) if isinstance(other, Tensor) else pow_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def __and__(self, other: "Tensor") -> "Tensor":
        return self.mul(other)

    def __or__(self, other: "Tensor") -> "Tensor":
        return self.add(other).clamp(0.0, 1.0)

    def __xor__(self, other: "Tensor") -> "Tensor":
        return (self.__or__(other)).__sub__(self.__and__(other))

    def __invert__(self) -> "Tensor":
        from ._tensor_math_helpers import invert_from_tensor
        return invert_from_tensor(self)

    def matmul(self, other: "Tensor") -> "Tensor":
        from .tensor_ops import matmul_from_tensors
        from ._complex import is_complex, matmul as _cmatmul
        if is_complex(self) or is_complex(other):
            return _cmatmul(self, other)
        return _ai2ai_matmul(self, other, matmul_from_tensors)

    def mm(self, other: "Tensor") -> "Tensor":
        return self.matmul(other)

    def bmm(self, other: "Tensor") -> "Tensor":
        return self.matmul(other)

    def mv(self, other: "Tensor") -> "Tensor":
        return self.matmul(other)

    def dot(self, other: "Tensor") -> "Tensor":
        return (self * other).sum()

    def outer(self, other: "Tensor") -> "Tensor":
        return self.reshape(-1, 1) * other.reshape(1, -1)

    def norm(self, p: float | str = "fro", dim=None, keepdim: bool = False) -> "Tensor":
        from ._tensor_math_helpers import norm_from_tensor
        if dim is None:
            return norm_from_tensor(self, p)
        q = 2.0 if p in ("fro", None) else float(p)  # ai2ai: vector norm along dim
        return self.abs().pow(q).sum(dim=dim, keepdim=keepdim).pow(1.0 / q)

    def cholesky(self) -> "Tensor":
        from ._tensor_runtime_bridge import cholesky_from_tensor
        return cholesky_from_tensor(self)

    def add(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import add_from_tensors, _scalar_to_tensor, _sdt
        from ._complex import is_complex, add as _cadd
        if is_complex(self) or is_complex(other):
            return _cadd(self, other)
        b_tensor = other if isinstance(other, Tensor) else _scalar_to_tensor(float(other), _sdt(other, self._dtype))
        return add_from_tensors(self, b_tensor)

    def sub(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import sub_from_tensors, _scalar_to_tensor, _sdt
        from ._complex import is_complex, sub as _csub
        if is_complex(self) or is_complex(other):
            return _csub(self, other)
        b_tensor = other if isinstance(other, Tensor) else _scalar_to_tensor(float(other), _sdt(other, self._dtype))
        return sub_from_tensors(self, b_tensor)

    def mul(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import mul_from_tensors, _scalar_to_tensor, _sdt
        from ._complex import is_complex, mul as _cmul
        if is_complex(self) or is_complex(other):
            return _cmul(self, other)
        b_tensor = other if isinstance(other, Tensor) else _scalar_to_tensor(float(other), _sdt(other, self._dtype))
        return mul_from_tensors(self, b_tensor)

    def div(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import div_from_tensors, _scalar_to_tensor, _sdt
        from ._complex import is_complex, div as _cdiv
        if is_complex(self) or is_complex(other):
            return _cdiv(self, other)
        b_tensor = other if isinstance(other, Tensor) else _scalar_to_tensor(float(other), _sdt(other, self._dtype))
        return div_from_tensors(self, b_tensor)

    def lu(self) -> tuple["Tensor", "Tensor"]:
        from ._tensor_runtime_bridge import lu_from_tensor
        return lu_from_tensor(self)

    def triangular_solve(self, b: "Tensor", upper: bool = False) -> "Tensor":
        from ._tensor_runtime_bridge import triangular_solve_from_tensors
        return triangular_solve_from_tensors(self, b, upper)

    def item(self) -> float:
        from ._tensor_runtime_bridge import item_from_tensor
        from ._complex import is_complex, to_complex_list
        if is_complex(self):
            flat = to_complex_list(self)
            while isinstance(flat, list):
                flat = flat[0]
            return flat
        return item_from_tensor(self)

    def det(self) -> "Tensor":
        from ._tensor_linalg_py import det_from_tensor
        return det_from_tensor(self)

    def inv(self) -> "Tensor":
        from ._tensor_linalg_py import inv_from_tensor
        return inv_from_tensor(self)

    def diag(self) -> "Tensor":
        from ._tensor_linalg_py import diag_from_tensor
        return diag_from_tensor(self)

    def diagonal(self, offset: int = 0, dim1: int = -2, dim2: int = -1) -> "Tensor":
        from .tensor_factories_ops import tensor_from_data

        shape = list(self.shape)
        ndim = len(shape)
        d1 = dim1 % ndim
        d2 = dim2 % ndim
        n = shape[d1]
        m = shape[d2]
        if offset >= 0:
            diag_len = max(0, min(n, m - offset))
            i0, j0 = 0, offset
        else:
            diag_len = max(0, min(n + offset, m))
            i0, j0 = -offset, 0

        nested = self.tolist()
        # Flatten according to shape to a 1D list.
        def _flatten(value: object, rest_shape: list[int]) -> list[float]:
            if not rest_shape:
                return [value]  # type: ignore[list-item]
            out: list[float] = []
            for sub in value:  # type: ignore[union-attr]
                out.extend(_flatten(sub, rest_shape[1:]))
            return out

        flat = _flatten(nested, shape)
        strides: list[int] = [1]
        for s in reversed(shape[1:]):
            strides.insert(0, strides[0] * s)
        inner_dims = [d for d in range(ndim) if d != d1 and d != d2]
        if diag_len == 0:
            new_shape = [shape[d] for d in inner_dims] + [0]
            return tensor_from_data([], new_shape, dtype=self._dtype)

        result_nested: object = []

        def _coord(idx: int) -> list[int]:
            c = [0] * ndim
            for d in range(ndim - 1, -1, -1):
                c[d] = idx % shape[d]
                idx //= shape[d]
            return c

        def _get(coord: list[int]) -> float:
            return flat[sum(coord[d] * strides[d] for d in range(ndim))]

        def _build(prefix: list[int]) -> object:
            if len(prefix) == len(inner_dims):
                out = []
                for k in range(diag_len):
                    coord = (
                        prefix[:d1]
                        + [i0 + k]
                        + prefix[d1 : d2 - 1]
                        + [j0 + k]
                        + prefix[d2 - 1 :]
                    )
                    out.append(_get(coord))
                return out
            out = []
            for i in range(shape[inner_dims[len(prefix)]]):
                out.append(_build(prefix + [i]))
            return out

        result_nested = _build([])
        new_shape = [shape[d] for d in inner_dims] + [diag_len]
        return tensor_from_data(result_nested, new_shape, dtype=self._dtype)

    def pow(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import pow_from_tensors, _scalar_to_tensor, _sdt
        return pow_from_tensors(self, other) if isinstance(other, Tensor) else pow_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def atan2(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import atan2_from_tensors, _scalar_to_tensor, _sdt
        return atan2_from_tensors(self, other) if isinstance(other, Tensor) else atan2_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def hypot(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import hypot_from_tensors, _scalar_to_tensor, _sdt
        return hypot_from_tensors(self, other) if isinstance(other, Tensor) else hypot_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def fmod(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import fmod_from_tensors, _scalar_to_tensor, _sdt
        return fmod_from_tensors(self, other) if isinstance(other, Tensor) else fmod_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def remainder(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import remainder_from_tensors, _scalar_to_tensor, _sdt
        return remainder_from_tensors(self, other) if isinstance(other, Tensor) else remainder_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def fmax(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import maximum_from_tensors, _scalar_to_tensor, _sdt
        return maximum_from_tensors(self, other) if isinstance(other, Tensor) else maximum_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def fmin(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import minimum_from_tensors, _scalar_to_tensor, _sdt
        return minimum_from_tensors(self, other) if isinstance(other, Tensor) else minimum_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def logaddexp(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import logaddexp_from_tensors, _scalar_to_tensor, _sdt
        return logaddexp_from_tensors(self, other) if isinstance(other, Tensor) else logaddexp_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def logaddexp2(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import logaddexp2_from_tensors, _scalar_to_tensor, _sdt
        return logaddexp2_from_tensors(self, other) if isinstance(other, Tensor) else logaddexp2_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def lerp(self, end: "Tensor | float", weight: "Tensor | float" = 0.5) -> "Tensor":
        from .tensor_ops import lerp_from_tensors, _scalar_to_tensor, _sdt
        if isinstance(end, Tensor):
            end_t = end
        else:
            end_t = _scalar_to_tensor(float(end), _sdt(end, self._dtype))
        if isinstance(weight, Tensor):
            weight_arg: "Tensor | float" = weight
        else:
            weight_arg = float(weight)
        return lerp_from_tensors(self, end_t, weight_arg)

    def addcmul(self, t1: "Tensor", t2: "Tensor", value: float = 1.0) -> "Tensor":
        from .tensor_ops import addcmul_from_tensors
        return addcmul_from_tensors(self, t1, t2, value)

    def addcdiv(self, t1: "Tensor", t2: "Tensor", value: float = 1.0) -> "Tensor":
        from .tensor_ops import addcdiv_from_tensors
        return addcdiv_from_tensors(self, t1, t2, value)

    def xlogy(self, y: "Tensor | float") -> "Tensor":
        from .tensor_ops import xlogy_from_tensors, _scalar_to_tensor, _sdt
        return xlogy_from_tensors(self, y) if isinstance(y, Tensor) else xlogy_from_tensors(self, _scalar_to_tensor(float(y), _sdt(y, self._dtype)))

    def copysign(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import copysign_from_tensors, _scalar_to_tensor, _sdt
        return copysign_from_tensors(self, other) if isinstance(other, Tensor) else copysign_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def nextafter(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import nextafter_from_tensors, _scalar_to_tensor, _sdt
        return nextafter_from_tensors(self, other) if isinstance(other, Tensor) else nextafter_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def floor_divide(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import floor_divide_from_tensors, _scalar_to_tensor, _sdt
        return floor_divide_from_tensors(self, other) if isinstance(other, Tensor) else floor_divide_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def true_divide(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import true_divide_from_tensors, _scalar_to_tensor, _sdt
        return true_divide_from_tensors(self, other) if isinstance(other, Tensor) else true_divide_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def logical_and(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import logical_and_from_tensors, _scalar_to_tensor, _sdt
        return logical_and_from_tensors(self, other) if isinstance(other, Tensor) else logical_and_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def logical_or(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import logical_or_from_tensors, _scalar_to_tensor, _sdt
        return logical_or_from_tensors(self, other) if isinstance(other, Tensor) else logical_or_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def logical_xor(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import logical_xor_from_tensors, _scalar_to_tensor, _sdt
        return logical_xor_from_tensors(self, other) if isinstance(other, Tensor) else logical_xor_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def bitwise_and(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import bitwise_and_from_tensors, _scalar_to_tensor, _sdt
        return bitwise_and_from_tensors(self, other) if isinstance(other, Tensor) else bitwise_and_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def bitwise_or(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import bitwise_or_from_tensors, _scalar_to_tensor, _sdt
        return bitwise_or_from_tensors(self, other) if isinstance(other, Tensor) else bitwise_or_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def bitwise_xor(self, other: "Tensor | float") -> "Tensor":
        from .tensor_ops import bitwise_xor_from_tensors, _scalar_to_tensor, _sdt
        return bitwise_xor_from_tensors(self, other) if isinstance(other, Tensor) else bitwise_xor_from_tensors(self, _scalar_to_tensor(float(other), _sdt(other, self._dtype)))

    def bitwise_not(self) -> "Tensor":
        from .tensor_ops import bitwise_not_from_tensor
        return bitwise_not_from_tensor(self)

    def heaviside(self, values: "Tensor") -> "Tensor":
        from .tensor_ops import heaviside_from_tensors
        return heaviside_from_tensors(self, values)

    def maximum(self, other: "Tensor") -> "Tensor":
        from .tensor_ops import maximum_from_tensors
        return maximum_from_tensors(self, other)

    def minimum(self, other: "Tensor") -> "Tensor":
        from .tensor_ops import minimum_from_tensors
        return minimum_from_tensors(self, other)

    def any(self) -> "Tensor":
        from .tensor_ops import any_from_tensor
        return any_from_tensor(self)

    def all(self) -> "Tensor":
        from .tensor_ops import all_from_tensor
        return all_from_tensor(self)

    def cumsum(self, dim: int = 0) -> "Tensor":
        from .tensor_ops import cumsum_from_tensor
        return cumsum_from_tensor(self, dim)

    def cumprod(self, dim: int = 0) -> "Tensor":
        from .tensor_ops import cumprod_from_tensor
        return cumprod_from_tensor(self, dim)

    def tril(self, diagonal: int = 0) -> "Tensor":
        from .tensor_ops import tril_from_tensor
        return tril_from_tensor(self, diagonal)

    def triu(self, diagonal: int = 0) -> "Tensor":
        from .tensor_ops import triu_from_tensor
        return triu_from_tensor(self, diagonal)

    def flip(self, dims: Sequence[int]) -> "Tensor":
        from .tensor_ops import flip_from_tensor
        return flip_from_tensor(self, dims)

    def where(self, condition: "Tensor", other: "Tensor") -> "Tensor":
        from .tensor_ops import where_from_tensors
        return where_from_tensors(condition, self, other)

    def cat(self, other: "Tensor", dim: int = 0) -> "Tensor":
        from .tensor_ops import cat_from_tensors
        return cat_from_tensors([self, other], dim)

    def stack(self, other: "Tensor", dim: int = 0) -> "Tensor":
        from .tensor_ops import stack_from_tensors
        return stack_from_tensors([self, other], dim)

    def index_select(self, dim: int, index: "Tensor") -> "Tensor":
        from .tensor_ops import index_select_from_tensor
        return index_select_from_tensor(self, dim, index)

    def index_add_(self, dim: int, index: "Tensor", source: "Tensor") -> "Tensor":
        from .tensor_ops import index_add_from_tensor
        return index_add_from_tensor(self, dim, index, source)

    def index_copy_(self, dim: int, index: "Tensor", source: "Tensor") -> "Tensor":
        from .tensor_ops import index_copy_from_tensor
        return index_copy_from_tensor(self, dim, index, source)

    def index_fill_(self, dim: int, index: "Tensor", value: "Tensor | float") -> "Tensor":
        from .tensor_ops import index_fill_from_tensor
        return index_fill_from_tensor(self, dim, index, value)

    def take(self, index: "Tensor") -> "Tensor":
        from .tensor_ops import take_from_tensor
        return take_from_tensor(self, index)

    def unfold(self, dimension: int, size: int, step: int = 1) -> "Tensor":
        from .tensor_ops import unfold_from_tensor
        return unfold_from_tensor(self, dimension, size, step)

    def empty_like(self) -> "Tensor":
        from .tensor_factories_ops import empty_like_from_tensor
        return empty_like_from_tensor(self)

    def zeros_like(self) -> "Tensor":
        from .tensor_factories_ops import zeros_like_from_tensor
        return zeros_like_from_tensor(self)

    def ones_like(self) -> "Tensor":
        from .tensor_factories_ops import ones_like_from_tensor
        return ones_like_from_tensor(self)

    def relu(self) -> "Tensor":
        from .tensor_ops import relu_from_tensor
        return relu_from_tensor(self)

    def abs(self) -> "Tensor":
        from .tensor_ops import abs_from_tensor
        from ._complex import is_complex, abs as _cabs
        if is_complex(self):
            return _cabs(self)
        return abs_from_tensor(self)

    def sqrt(self) -> "Tensor":
        from .tensor_ops import sqrt_from_tensor
        return sqrt_from_tensor(self)

    def exp(self) -> "Tensor":
        from .tensor_ops import exp_from_tensor
        return exp_from_tensor(self)

    def log(self) -> "Tensor":
        from .tensor_ops import log_from_tensor
        return log_from_tensor(self)

    def neg(self) -> "Tensor":
        from .tensor_ops import neg_from_tensor
        from ._complex import is_complex, neg as _cneg
        if is_complex(self):
            return _cneg(self)
        return neg_from_tensor(self)

    @property
    def real(self) -> "Tensor":
        from ._complex import real as _creal
        return _creal(self)

    @property
    def imag(self) -> "Tensor":
        from ._complex import imag as _cimag
        return _cimag(self)

    def conj(self) -> "Tensor":
        from ._complex import conj as _cconj
        return _cconj(self)

    def angle(self) -> "Tensor":
        from ._complex import angle as _cangle
        return _cangle(self)

    def is_complex(self) -> bool:
        from ._complex import is_complex
        return is_complex(self)

    def clamp(self, min: float | None = None, max: float | None = None) -> "Tensor":
        from ._tensor_runtime_bridge import clamp_from_tensor
        if min is None and max is None:
            raise TypeError("clamp() requires at least one of 'min' or 'max'")
        lo = -float("inf") if min is None else float(min)
        hi = float("inf") if max is None else float(max)
        return clamp_from_tensor(self, lo, hi)

    def argmax(self, dim: int | None = None, keepdim: bool = False) -> "Tensor":
        from ._tensor_runtime_bridge import argmax_from_tensor
        if dim is None and not keepdim:
            return argmax_from_tensor(self)
        return argmax_from_tensor(self, dim=dim, keepdim=keepdim)

    def argmin(self, dim: int | None = None, keepdim: bool = False) -> "Tensor":
        from ._tensor_runtime_bridge import argmin_from_tensor
        if dim is None and not keepdim:
            return argmin_from_tensor(self)
        return argmin_from_tensor(self, dim=dim, keepdim=keepdim)

    def reshape(self, *shape: int | Sequence[int]) -> "Tensor":
        from ._tensor_runtime_bridge import reshape_from_tensor
        from .tensor_shape_utils import _normalize_reshape_shape_from_args
        normalized = _normalize_reshape_shape_from_args(shape, self._shape)
        return reshape_from_tensor(self, normalized)

    def view(self, *shape: int) -> "Tensor":
        from .tensor_shape_utils import _normalize_reshape_shape_from_args
        normalized = _normalize_reshape_shape_from_args(shape, self._shape)
        return self.reshape(normalized)

    def flatten(self, start_dim: int = 0, end_dim: int = -1) -> "Tensor":
        from ._tensor_runtime_bridge import flatten_from_tensor
        return flatten_from_tensor(self, start_dim, end_dim)

    def squeeze(self, dim: int | None = None) -> "Tensor":
        from ._tensor_runtime_bridge import squeeze_from_tensor
        return squeeze_from_tensor(self, dim)

    def unsqueeze(self, dim: int) -> "Tensor":
        from ._tensor_runtime_bridge import unsqueeze_from_tensor
        return unsqueeze_from_tensor(self, dim)

    def transpose(self, dim0: int, dim1: int) -> "Tensor":
        from ._tensor_runtime_bridge import transpose_from_tensor
        return transpose_from_tensor(self, dim0, dim1)

    def permute(self, *dims) -> "Tensor":
        from ._tensor_runtime_bridge import permute_from_tensor
        if len(dims) == 1 and isinstance(dims[0], (list, tuple)):
            dims = dims[0]
        return permute_from_tensor(self, [int(d) for d in dims])

    def expand(self, *shape: int) -> "Tensor":
        from .tensor_shape_utils import _normalize_shape_from_args
        from .tensor_ops import expand_from_tensor
        return expand_from_tensor(self, _normalize_shape_from_args(shape))

    def expand_as(self, other: "Tensor") -> "Tensor":
        return self.expand(*other._shape)

    def select(self, dim: int, index: int) -> "Tensor":
        from .tensor_ops import select_from_tensor
        return select_from_tensor(self, dim, index)

    def slice(self, dim: int, start: int | None = None, end: int | None = None, step: int = 1) -> "Tensor":
        from .tensor_ops import slice_from_tensor
        return slice_from_tensor(self, dim, start, end, step)

    @property
    def T(self) -> "Tensor":
        from ._tensor_runtime_bridge import t_from_tensor
        return t_from_tensor(self)

    def tolist(self) -> object:
        from ._tensor_runtime_bridge import tolist_from_tensor
        return tolist_from_tensor(self)

    def numpy(self, *, force: bool = False):
        import numpy as np
        if self.requires_grad and not force:
            raise RuntimeError("Can't call numpy() on Tensor that requires grad. Use tensor.detach().numpy() instead.")
        return np.array(self.tolist(), dtype=self._dtype.encode().decode().replace("torch.", ""))

    def split(self, split_size: int | list[int], dim: int = 0) -> list["Tensor"]:
        from ._tensor_shape_ops import split_from_tensor
        return split_from_tensor(self, split_size, dim)

    def chunk(self, chunks: int, dim: int = 0) -> list["Tensor"]:
        from ._tensor_shape_ops import chunk_from_tensor
        return chunk_from_tensor(self, chunks, dim)

    def destroy(self) -> None:
        from ._tensor_runtime_bridge import destroy_tensor
        destroy_tensor(self)

    def sigmoid(self) -> "Tensor":
        from .tensor_ops import sigmoid_from_tensor
        return sigmoid_from_tensor(self)

    def tanh(self) -> "Tensor":
        from .tensor_ops import tanh_from_tensor
        return tanh_from_tensor(self)

    def sin(self) -> "Tensor":
        from .tensor_ops import sin_from_tensor
        return sin_from_tensor(self)

    def cos(self) -> "Tensor":
        from .tensor_ops import cos_from_tensor
        return cos_from_tensor(self)

    def gelu(self) -> "Tensor":
        from .tensor_ops import gelu_from_tensor
        return gelu_from_tensor(self)

    def silu(self) -> "Tensor":
        from .tensor_ops import silu_from_tensor
        return silu_from_tensor(self)

    def softmax(self, dim: int = -1) -> "Tensor":
        from .tensor_ops import softmax_from_tensor
        return softmax_from_tensor(self, dim)

    def log_softmax(self, dim: int = -1) -> "Tensor":
        from .tensor_ops import log_softmax_from_tensor
        return log_softmax_from_tensor(self, dim)

    def leaky_relu(self, alpha: float = 0.01) -> "Tensor":
        from .tensor_ops import leaky_relu_from_tensor
        return leaky_relu_from_tensor(self, alpha)

    def floor(self) -> "Tensor":
        from .tensor_ops import floor_from_tensor
        return floor_from_tensor(self)

    def ceil(self) -> "Tensor":
        from .tensor_ops import ceil_from_tensor
        return ceil_from_tensor(self)

    def round(self, decimals: int = 0) -> "Tensor":
        from .tensor_ops import round_from_tensor
        if decimals:  # as PyTorch does it: scale, round half to even, scale back
            k = 10.0 ** decimals
            return round_from_tensor(self * k) / k
        return round_from_tensor(self)

    def reciprocal(self) -> "Tensor":
        from .tensor_ops import reciprocal_from_tensor
        return reciprocal_from_tensor(self)

    def square(self) -> "Tensor":
        from .tensor_ops import square_from_tensor
        return square_from_tensor(self)

    def tan(self) -> "Tensor":
        from .tensor_ops import tan_from_tensor
        return tan_from_tensor(self)

    def asin(self) -> "Tensor":
        from .tensor_ops import asin_from_tensor
        return asin_from_tensor(self)

    def acos(self) -> "Tensor":
        from .tensor_ops import acos_from_tensor
        return acos_from_tensor(self)

    def atan(self) -> "Tensor":
        from .tensor_ops import atan_from_tensor
        return atan_from_tensor(self)

    def sinh(self) -> "Tensor":
        from .tensor_ops import sinh_from_tensor
        return sinh_from_tensor(self)

    def cosh(self) -> "Tensor":
        from .tensor_ops import cosh_from_tensor
        return cosh_from_tensor(self)

    def asinh(self) -> "Tensor":
        from .tensor_ops import asinh_from_tensor
        return asinh_from_tensor(self)

    def acosh(self) -> "Tensor":
        from .tensor_ops import acosh_from_tensor
        return acosh_from_tensor(self)

    def atanh(self) -> "Tensor":
        from .tensor_ops import atanh_from_tensor
        return atanh_from_tensor(self)

    def exp2(self) -> "Tensor":
        from .tensor_ops import exp2_from_tensor
        return exp2_from_tensor(self)

    def log2(self) -> "Tensor":
        from .tensor_ops import log2_from_tensor
        return log2_from_tensor(self)

    def log10(self) -> "Tensor":
        from .tensor_ops import log10_from_tensor
        return log10_from_tensor(self)

    def log1p(self) -> "Tensor":
        from .tensor_ops import log1p_from_tensor
        return log1p_from_tensor(self)

    def expm1(self) -> "Tensor":
        from .tensor_ops import expm1_from_tensor
        return expm1_from_tensor(self)

    def trunc(self) -> "Tensor":
        from .tensor_ops import trunc_from_tensor
        return trunc_from_tensor(self)

    def frac(self) -> "Tensor":
        from .tensor_ops import frac_from_tensor
        return frac_from_tensor(self)

    def softplus(self) -> "Tensor":
        from .tensor_ops import softplus_from_tensor
        return softplus_from_tensor(self)

    def mish(self) -> "Tensor":
        from .tensor_ops import mish_from_tensor
        return mish_from_tensor(self)

    def hardsigmoid(self) -> "Tensor":
        from .tensor_ops import hardsigmoid_from_tensor
        return hardsigmoid_from_tensor(self)

    def hardswish(self) -> "Tensor":
        from .tensor_ops import hardswish_from_tensor
        return hardswish_from_tensor(self)

    def softsign(self) -> "Tensor":
        from .tensor_ops import softsign_from_tensor
        return softsign_from_tensor(self)

    def tanhshrink(self) -> "Tensor":
        from .tensor_ops import tanhshrink_from_tensor
        return tanhshrink_from_tensor(self)

    def rsqrt(self) -> "Tensor":
        from .tensor_ops import rsqrt_from_tensor
        return rsqrt_from_tensor(self)

    def sign(self) -> "Tensor":
        from .tensor_ops import sign_from_tensor
        return sign_from_tensor(self)

    def sgn(self) -> "Tensor":
        from .tensor_ops import sgn_from_tensor
        return sgn_from_tensor(self)

    def isnan(self) -> "Tensor":
        from .tensor_ops import isnan_from_tensor
        return isnan_from_tensor(self)

    def isinf(self) -> "Tensor":
        from .tensor_ops import isinf_from_tensor
        return isinf_from_tensor(self)

    def isfinite(self) -> "Tensor":
        from .tensor_ops import isfinite_from_tensor
        return isfinite_from_tensor(self)

    def isposinf(self) -> "Tensor":
        from .tensor_ops import isposinf_from_tensor
        return isposinf_from_tensor(self)

    def isneginf(self) -> "Tensor":
        from .tensor_ops import isneginf_from_tensor
        return isneginf_from_tensor(self)

    def logical_not(self) -> "Tensor":
        from .tensor_ops import logical_not_from_tensor
        return logical_not_from_tensor(self)

    def erf(self) -> "Tensor":
        from .tensor_ops import erf_from_tensor
        return erf_from_tensor(self)

    def erfc(self) -> "Tensor":
        from .tensor_ops import erfc_from_tensor
        return erfc_from_tensor(self)

    def lgamma(self) -> "Tensor":
        from .tensor_ops import lgamma_from_tensor
        return lgamma_from_tensor(self)

    def digamma(self) -> "Tensor":
        from .tensor_ops import digamma_from_tensor
        return digamma_from_tensor(self)

    def i0(self) -> "Tensor":
        from .tensor_ops import i0_from_tensor
        return i0_from_tensor(self)

    def deg2rad(self) -> "Tensor":
        from .tensor_ops import deg2rad_from_tensor
        return deg2rad_from_tensor(self)

    def rad2deg(self) -> "Tensor":
        from .tensor_ops import rad2deg_from_tensor
        return rad2deg_from_tensor(self)

    def eq(self, other: "Tensor") -> "Tensor":
        from .tensor_ops import eq_from_tensors
        return eq_from_tensors(self, other)

    def ne(self, other: "Tensor") -> "Tensor":
        from .tensor_ops import ne_from_tensors
        return ne_from_tensors(self, other)

    def gt(self, other: "Tensor | int | float") -> "Tensor":
        import torch as _torch
        if not isinstance(other, Tensor):
            other = _torch.tensor(other, dtype=self._dtype)
        from .tensor_ops import gt_from_tensors
        return gt_from_tensors(self, other)

    def lt(self, other: "Tensor | int | float") -> "Tensor":
        import torch as _torch
        if not isinstance(other, Tensor):
            other = _torch.tensor(other, dtype=self._dtype)
        from .tensor_ops import lt_from_tensors
        return lt_from_tensors(self, other)

    def ge(self, other: "Tensor | int | float") -> "Tensor":
        import torch as _torch
        if not isinstance(other, Tensor):
            other = _torch.tensor(other, dtype=self._dtype)
        from .tensor_ops import ge_from_tensors
        return ge_from_tensors(self, other)

    def le(self, other: "Tensor | int | float") -> "Tensor":
        import torch as _torch
        if not isinstance(other, Tensor):
            other = _torch.tensor(other, dtype=self._dtype)
        from .tensor_ops import le_from_tensors
        return le_from_tensors(self, other)

    def sum(self, dim: int | None = None, keepdim: bool = False) -> "Tensor":
        if dim is not None:
            from .tensor_ops import sum_dim_from_tensor
            return sum_dim_from_tensor(self, dim, keepdim)
        from .tensor_ops import sum_from_tensor
        return sum_from_tensor(self)

    def mean(self, dim: int | None = None, keepdim: bool = False) -> "Tensor":
        if dim is not None:
            from .tensor_ops import mean_dim_from_tensor
            return mean_dim_from_tensor(self, dim, keepdim)
        from .tensor_ops import mean_from_tensor
        return mean_from_tensor(self)

    def prod(self) -> "Tensor":
        from .tensor_ops import prod_from_tensor
        return prod_from_tensor(self)

    def min(self, dim: int | None = None, keepdim: bool = False):
        if dim is not None:
            from .tensor_ops import min_dim_from_tensor
            return min_dim_from_tensor(self, dim, keepdim)
        from .tensor_ops import min_from_tensor
        return min_from_tensor(self)

    def max(self, dim: int | None = None, keepdim: bool = False):
        if dim is not None:
            from .tensor_ops import max_dim_from_tensor
            return max_dim_from_tensor(self, dim, keepdim)
        from .tensor_ops import max_from_tensor
        return max_from_tensor(self)

    def amax(self, dim=None, keepdim: bool = False) -> "Tensor":
        from .tensor_ops import amax_from_tensor
        return amax_from_tensor(self, dim, keepdim)

    def amin(self, dim=None, keepdim: bool = False) -> "Tensor":
        from .tensor_ops import amin_from_tensor
        return amin_from_tensor(self, dim, keepdim)

    def logsumexp(self, dim, keepdim: bool = False) -> "Tensor":
        from .tensor_ops import amax_from_tensor
        ndim = len(self._shape)
        dims = [dim] if isinstance(dim, int) else list(dim)
        dims = sorted((d if d >= 0 else d + ndim) for d in dims)
        m = amax_from_tensor(self, dims, keepdim=True)
        m_fixed = m.nan_to_num(posinf=0.0, neginf=0.0)
        out = (self - m_fixed).exp()
        for d in dims:
            out = out.sum(dim=d, keepdim=True)
        out = out.log() + m_fixed
        if not keepdim:
            for d in reversed(dims):
                out = out.squeeze(d)
        return out

    def var(self, dim=None, keepdim: bool = False, correction: int = 1, unbiased: bool | None = None) -> "Tensor":
        from .tensor_ops import var_from_tensor
        if unbiased is not None:
            correction = 1 if unbiased else 0
        out = var_from_tensor(self, dim, keepdim, correction)
        if dim is None and not keepdim and list(out._shape) == [1]:
            out = out.reshape([])  # ai2ai: full reductions are 0-d, as in PyTorch
        return out

    def std(self, dim=None, keepdim: bool = False, correction: int = 1, unbiased: bool | None = None) -> "Tensor":
        return self.var(dim=dim, keepdim=keepdim, correction=correction, unbiased=unbiased).sqrt()

    def nan_to_num(self, nan: float = 0.0, posinf: float | None = None, neginf: float | None = None) -> "Tensor":
        from .tensor_ops import nan_to_num_from_tensor
        return nan_to_num_from_tensor(self, nan, posinf, neginf)

    def unbind(self, dim: int = 0) -> tuple["Tensor", ...]:
        d = dim if dim >= 0 else dim + len(self._shape)
        return tuple(self.select(d, i) for i in range(self._shape[d]))

    def movedim(self, source, destination) -> "Tensor":
        from .tensor_ops import movedim_from_tensor
        return movedim_from_tensor(self, source, destination)

    def moveaxis(self, source, destination) -> "Tensor":
        from .tensor_ops import movedim_from_tensor
        return movedim_from_tensor(self, source, destination)

    def swapaxes(self, axis0: int, axis1: int) -> "Tensor":
        return self.transpose(axis0, axis1)

    def swapdims(self, dim0: int, dim1: int) -> "Tensor":
        return self.transpose(dim0, dim1)

    def ravel(self) -> "Tensor":
        return self.reshape([-1])

    def count_nonzero(self, dim=None) -> "Tensor":
        import torch as _torch
        mask = self.ne(_torch.tensor(0, dtype=self._dtype)).to("int64")
        if dim is None:
            return mask.sum()
        return mask.sum(dim=dim)

    def signbit(self) -> "Tensor":
        import torch as _torch
        return self.lt(_torch.tensor(0, dtype=self._dtype))

    def positive(self) -> "Tensor":
        return self

    def negative(self) -> "Tensor":
        return self.neg()

    def clamp_min(self, min) -> "Tensor":
        return self.clamp(min=min)

    def clamp_max(self, max) -> "Tensor":
        return self.clamp(max=max)

    def clip(self, min=None, max=None) -> "Tensor":
        return self.clamp(min=min, max=max)

    def float_power(self, exponent) -> "Tensor":
        return self.pow(exponent)

    def aminmax(self, dim=None, keepdim: bool = False):
        return (self.amin(dim, keepdim), self.amax(dim, keepdim))

    def diff(self, n: int = 1, dim: int = -1) -> "Tensor":
        import torch as _torch
        return _torch.diff(self, n=n, dim=dim)

    def trace(self) -> "Tensor":
        return self.diag().sum()

    def diagflat(self, offset: int = 0) -> "Tensor":
        return self.reshape([-1]).diag()

    def dist(self, other: "Tensor", p: float = 2) -> "Tensor":
        import torch as _torch
        return _torch.dist(self, other, p=p)

    def inner(self, other: "Tensor") -> "Tensor":
        import torch as _torch
        return _torch.inner(self, other)

    def kron(self, other: "Tensor") -> "Tensor":
        import torch as _torch
        return _torch.kron(self, other)

    def cross(self, other: "Tensor", dim: int | None = None) -> "Tensor":
        import torch as _torch
        return _torch.cross(self, other, dim=dim)

    def vdot(self, other: "Tensor") -> "Tensor":
        import torch as _torch
        return _torch.vdot(self, other)

    def take_along_dim(self, indices: "Tensor", dim: int) -> "Tensor":
        return self.gather(dim, indices)

    def flipud(self) -> "Tensor":
        return self.flip([0])

    def fliplr(self) -> "Tensor":
        return self.flip([1])

    def rot90(self, k: int = 1, dims=(0, 1)) -> "Tensor":
        import torch as _torch
        return _torch.rot90(self, k, dims)

    def renorm(self, p: float, dim: int, maxnorm: float) -> "Tensor":
        import torch as _torch
        return _torch.renorm(self, p, dim, maxnorm)

    def broadcast_to(self, shape) -> "Tensor":
        import torch as _torch
        return _torch.broadcast_to(self, shape)

    def sinc(self) -> "Tensor":
        import torch as _torch
        return _torch.sinc(self)

    def isreal(self) -> "Tensor":
        import torch as _torch
        return _torch.isreal(self)

    def nansum(self, dim=None, keepdim: bool = False) -> "Tensor":
        import torch as _torch
        return _torch.nansum(self, dim=dim, keepdim=keepdim)

    def nanmean(self, dim=None, keepdim: bool = False) -> "Tensor":
        import torch as _torch
        return _torch.nanmean(self, dim=dim, keepdim=keepdim)

    def tensor_split(self, indices_or_sections, dim: int = 0):
        import torch as _torch
        return _torch.tensor_split(self, indices_or_sections, dim=dim)

    def hsplit(self, indices_or_sections):
        import torch as _torch
        return _torch.hsplit(self, indices_or_sections)

    def vsplit(self, indices_or_sections):
        import torch as _torch
        return _torch.vsplit(self, indices_or_sections)

    def dsplit(self, indices_or_sections):
        import torch as _torch
        return _torch.dsplit(self, indices_or_sections)

    def diag_embed(self, offset: int = 0, dim1: int = -2, dim2: int = -1) -> "Tensor":
        import torch as _torch
        return _torch.diag_embed(self, offset, dim1, dim2)

    def addmm(self, mat1: "Tensor", mat2: "Tensor", beta: float = 1, alpha: float = 1) -> "Tensor":
        import torch as _torch
        return _torch.addmm(self, mat1, mat2, beta=beta, alpha=alpha)

    def addmv(self, mat: "Tensor", vec: "Tensor", beta: float = 1, alpha: float = 1) -> "Tensor":
        import torch as _torch
        return _torch.addmv(self, mat, vec, beta=beta, alpha=alpha)

    def baddbmm(self, batch1: "Tensor", batch2: "Tensor", beta: float = 1, alpha: float = 1) -> "Tensor":
        import torch as _torch
        return _torch.baddbmm(self, batch1, batch2, beta=beta, alpha=alpha)

    def addbmm(self, batch1: "Tensor", batch2: "Tensor", beta: float = 1, alpha: float = 1) -> "Tensor":
        import torch as _torch
        return _torch.addbmm(self, batch1, batch2, beta=beta, alpha=alpha)

    def masked_select(self, mask: "Tensor") -> "Tensor":
        from .tensor_ops import masked_select_from_tensor
        return masked_select_from_tensor(self, mask)

    def masked_fill(self, mask: "Tensor", value: float) -> "Tensor":
        from .tensor_ops import masked_fill_from_tensor
        if list(mask.shape) != list(self._shape):
            # ai2ai: broadcast the mask like PyTorch does
            import torch
            mask = (mask.float() + torch.zeros(list(self._shape))) > 0.5
        return masked_fill_from_tensor(self, mask, value)

    def nonzero(self) -> "Tensor":
        from .tensor_ops import nonzero_from_tensor
        return nonzero_from_tensor(self)

    def roll(self, shifts: int | list[int], dims: int | list[int] | None = None) -> "Tensor":
        from .tensor_ops import roll_from_tensor
        return roll_from_tensor(self, shifts, dims)

    def kthvalue(self, k: int, dim: int = -1):
        from .tensor_ops import kthvalue_from_tensor
        return kthvalue_from_tensor(self, k, dim)

    def median(self, dim=None):
        from .tensor_ops import median_from_tensor
        return median_from_tensor(self, dim)

    def mode(self, dim=None):
        from .tensor_ops import mode_from_tensor
        return mode_from_tensor(self, dim)

    def quantile(self, q, dim: int = -1):
        from .tensor_ops import quantile_from_tensor
        return quantile_from_tensor(self, q, dim)

    def equal(self, other: "Tensor") -> "Tensor":
        from .tensor_ops import equal_from_tensors
        return equal_from_tensors(self, other)

    def allclose(self, other: "Tensor", rtol: float = 1e-05, atol: float = 1e-08, equal_nan: bool = False) -> "Tensor":
        from .tensor_ops import allclose_from_tensors
        return allclose_from_tensors(self, other, rtol, atol, equal_nan)

    def isclose(self, other: "Tensor", rtol: float = 1e-05, atol: float = 1e-08, equal_nan: bool = False) -> "Tensor":
        from .tensor_ops import isclose_from_tensors
        return isclose_from_tensors(self, other, rtol, atol, equal_nan)

    def _set(self, other: "Tensor") -> None:
        self._id = other._id
        self._shape = list(other._shape)
        self._dtype = other._dtype
        if hasattr(self, "_data"):
            self._data = other

    def __getitem__(self, key: object) -> object:
        from ._tensor_indexing import getitem_from_tensor
        return getitem_from_tensor(self, key)

    # ── in-place arithmetic (ai2ai): x -= y changes x itself, as in PyTorch ──
    def _inplace(self, fn) -> "Tensor":
        import copy
        from .autograd import is_grad_enabled
        if not is_grad_enabled():
            res = fn(self)
            if res._dtype != self._dtype:
                res = res.to(self._dtype)
            self._set(res.detach())
            return self
        if self._requires_grad and self._node is None:
            raise RuntimeError("a leaf Variable that requires grad is being used in an in-place operation.")
        old = copy.copy(self)
        if old._node is not None:   # the earlier graph now ends at the copy
            old._node.tensor = old
        res = fn(old)
        if res._dtype != self._dtype:
            res = res.to(self._dtype)
        self._set(res)
        self._node = res._node
        self._requires_grad = res._requires_grad
        if res._node is not None:
            res._node.tensor = self
        return self

    def __iadd__(self, other): return self._inplace(lambda t: t + other)
    def __isub__(self, other): return self._inplace(lambda t: t - other)
    def __imul__(self, other): return self._inplace(lambda t: t * other)
    def __itruediv__(self, other): return self._inplace(lambda t: t / other)
    def __ipow__(self, other): return self._inplace(lambda t: t ** other)
    def add_(self, other, alpha=1): return self._inplace(lambda t: t + other * alpha if alpha != 1 else t + other)
    def sub_(self, other, alpha=1): return self._inplace(lambda t: t - other * alpha if alpha != 1 else t - other)
    def mul_(self, other): return self._inplace(lambda t: t * other)
    def div_(self, other): return self._inplace(lambda t: t / other)
    def pow_(self, other): return self._inplace(lambda t: t ** other)
    def neg_(self): return self._inplace(lambda t: -t)
    def abs_(self): return self._inplace(lambda t: t.abs())
    def sqrt_(self): return self._inplace(lambda t: t.sqrt())
    def exp_(self): return self._inplace(lambda t: t.exp())
    def log_(self): return self._inplace(lambda t: t.log())
    def clamp_(self, min=None, max=None): return self._inplace(lambda t: t.clamp(min, max))
    def relu_(self): return self._inplace(lambda t: t.relu())
    def sigmoid_(self): return self._inplace(lambda t: t.sigmoid())
    def tanh_(self): return self._inplace(lambda t: t.tanh())

    def __setitem__(self, key: object, value: object) -> None:
        from ._tensor_indexing import setitem_from_tensor
        setitem_from_tensor(self, key, value)


from .tensor_ops import (
    add_from_tensors,
    sub_from_tensors,
    mul_from_tensors,
    div_from_tensors,
    pow_from_tensors,
    heaviside_from_tensors,
    maximum_from_tensors,
    minimum_from_tensors,
    any_from_tensor,
    all_from_tensor,
    cumsum_from_tensor,
    cumprod_from_tensor,
    tril_from_tensor,
    triu_from_tensor,
    flip_from_tensor,
    where_from_tensors,
    topk_from_tensor,
    sort_from_tensor,
    gather_from_tensor,
    scatter_from_tensor,
    cat_from_tensors,
    stack_from_tensors,
    expand_from_tensor,
    index_select_from_tensor,
    sigmoid_from_tensor,
    tanh_from_tensor,
    sin_from_tensor,
    cos_from_tensor,
    gelu_from_tensor,
    silu_from_tensor,
    leaky_relu_from_tensor,
    floor_from_tensor,
    ceil_from_tensor,
    round_from_tensor,
    reciprocal_from_tensor,
    square_from_tensor,
    tan_from_tensor,
    asin_from_tensor,
    acos_from_tensor,
    atan_from_tensor,
    sinh_from_tensor,
    cosh_from_tensor,
    asinh_from_tensor,
    acosh_from_tensor,
    atanh_from_tensor,
    exp2_from_tensor,
    log2_from_tensor,
    log10_from_tensor,
    log1p_from_tensor,
    expm1_from_tensor,
    trunc_from_tensor,
    frac_from_tensor,
    softplus_from_tensor,
    mish_from_tensor,
    hardsigmoid_from_tensor,
    hardswish_from_tensor,
    softsign_from_tensor,
    tanhshrink_from_tensor,
    rsqrt_from_tensor,
    sign_from_tensor,
    sgn_from_tensor,
    isnan_from_tensor,
    isinf_from_tensor,
    isfinite_from_tensor,
    isposinf_from_tensor,
    isneginf_from_tensor,
    logical_not_from_tensor,
    erf_from_tensor,
    erfc_from_tensor,
    lgamma_from_tensor,
    digamma_from_tensor,
    i0_from_tensor,
    deg2rad_from_tensor,
    rad2deg_from_tensor,
    eq_from_tensors,
    ne_from_tensors,
    lt_from_tensors,
    le_from_tensors,
    gt_from_tensors,
    ge_from_tensors,
    sum_dim_from_tensor,
    sum_from_tensor,
    mean_from_tensor,
    mean_dim_from_tensor,
    prod_from_tensor,
    min_from_tensor,
    max_from_tensor,
    masked_select_from_tensor,
    masked_fill_from_tensor,
    softmax_from_tensor,
    log_softmax_from_tensor,
    relu_from_tensor,
    abs_from_tensor,
    sqrt_from_tensor,
    exp_from_tensor,
    log_from_tensor,
    neg_from_tensor,
    select_from_tensor,
    slice_from_tensor,
    matmul_from_tensors,
    _js_meta_to_tuple,
    _js_handle_array_to_tensors,
)

from .tensor_nn_ops import (
    conv2d_from_tensors,
    max_pool2d_from_tensor,
    avg_pool2d_from_tensor,
    batch_norm_from_tensor,
    nll_loss_from_tensor,
    cross_entropy_from_tensor,
    batch_norm_inference_from_tensor,
    layer_norm_from_tensor,
    group_norm_from_tensor,
)

from .tensor_backward_ops import (
    conv2d_input_backward_from_tensors,
    conv2d_weight_backward_from_tensors,
    conv2d_bias_backward_from_tensors,
    softmax_backward_from_tensors,
    log_softmax_backward_from_tensors,
    nll_loss_backward_from_tensors,
    slice_backward_from_tensors,
    sort_backward_from_tensors,
    topk_backward_from_tensors,
    cross_entropy_backward_from_tensors,
    maxmin_backward_from_tensors,
)
