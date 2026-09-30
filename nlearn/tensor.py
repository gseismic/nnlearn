import numpy as np
from . import backend
from .log import log_function_call
from .settings import Config, log_settings, runtime_settings, using_config
from . import functional as F
from .functional.get_item import get_item
#import networkx as nx
#import matplotlib.pyplot as plt


class Tensor:

    # 确保优先级高于np.ndarray的运算符
    __array_priority__ = 200

    def __init__(
        self, data, name=None, log_enabled=None, device=None, dtype=None,
        requires_grad=None,
    ):
        if isinstance(data, Tensor):
            if requires_grad is None:
                requires_grad = data.requires_grad
            data = data.data
        self.data = backend.ensure_array(data, device=device, dtype=dtype)
        if requires_grad is None:
            requires_grad = Config.enable_backprop
        self.requires_grad = requires_grad
        self.name = name
        if log_enabled is None:
            self.log_enabled = log_settings.get('tensor_log_enabled', False)
        else:
            self.log_enabled = log_enabled
        self.grad = None
        self.creator = None
        self.generation = 0

    def set_creator(self, func):
        # Tensor-output代始终比产生它的function大一代
        self.creator = func
        self.generation = self.creator.generation + 1

    def zero_grad(self):
        self.grad = None

    def requires_grad_(self, requires_grad=True):
        self.requires_grad = requires_grad
        return self

    @log_function_call(enabled=True)
    def backward(self, retain_grad=False, create_graph=False):
        if not self.requires_grad:
            return

        xp = backend.get_array_module(self.data)
        seed = Tensor(xp.ones_like(self.data), requires_grad=create_graph)
        with using_config('enable_backprop', create_graph):
            self.grad = seed if self.grad is None else self.grad + seed
        if self.creator is None:
            return

        funcs = []
        set_funcs = set()
        # 每次反向传播只传递本次新产生的梯度，避免复用保留的旧梯度。
        current_grads = {id(self): seed}
        def add_func(f):
            if f not in set_funcs:
                funcs.append(f)
                set_funcs.add(f)
                funcs.sort(key=lambda x: x.generation)

        add_func(self.creator)
        while funcs:
            f = funcs.pop() # pop the item with maximal generation
            if runtime_settings.get('remove_recursive_ref', True):
                outputs = [output() for output in f.outputs]
            else:
                outputs = f.outputs
            gys = [
                current_grads.get(id(output)) if output is not None else None
                for output in outputs
            ]

            # create_graph默认False: 默认单次backward后不需要再次反向传播了
            # enable_backprop 为了: `inputs` 仅仅在反向传播时才需要，不反向传播时，不用保留
            # 如果create_graph 为真，表示还需要导数值，所以
            with using_config('enable_backprop', create_graph):
                gxs = f.backward(*gys)
                if not isinstance(gxs, tuple):
                    gxs = (gxs, )

                for x, gx in zip(f.inputs, gxs):
                    if gx is None:
                        continue
                    if not x.requires_grad:
                        continue
                    key = id(x)
                    if key in current_grads:
                        current_grads[key] = current_grads[key] + gx
                    else:
                        current_grads[key] = gx
                    if x.grad is None:
                        x.grad = gx
                    else:
                        x.grad = x.grad + gx

                    if x.creator is not None:
                        add_func(x.creator)

            if not retain_grad:
                for output in outputs:
                    if output is not None:
                        output.grad = None

    def reshape(self, *shape):
        if len(shape) == 1 and isinstance(shape[0], (tuple,list)):
            shape = shape[0]
        return F.reshape(self, shape)

    def view(self, *shape):
        if len(shape) == 1 and isinstance(shape[0], (tuple,list)):
            shape = shape[0]
        return F.view(self, shape)

    def unsqueeze(self, dim):
        return F.unsqueeze(self, dim)

    def squeeze(self, dim=None, axis=None):
        return F.squeeze(self, dim=dim, axis=axis)

    def flatten(self, start_dim=0, end_dim=-1):
        return F.flatten(self, start_dim=start_dim, end_dim=end_dim)

    def repeat(self, *repeats):
        return F.repeat(self, *repeats)

    def split(self, split_size_or_sections, dim=0):
        return F.split(self, split_size_or_sections, dim=dim)

    def chunk(self, chunks, dim=0):
        return F.chunk(self, chunks, dim=dim)

    def transpose(self, dim0=None, dim1=None):
        return F.transpose(self, dim0, dim1)

    def permute(self, *dims):
        if len(dims) == 1 and isinstance(dims[0], (tuple,list)):
            dims = tuple(dims[0])
        return F.permute(self, dims)

    def sum(self, dim=None, axis=None, keepdim=False, keepdims=None):
        axis = dim if dim is not None else axis
        keepdim = keepdim if keepdims is None else keepdims
        return F.sum(self, axis=axis, keepdims=keepdim)

    def mean(self, dim=None, axis=None, keepdim=False, keepdims=None):
        axis = dim if dim is not None else axis
        keepdim = keepdim if keepdims is None else keepdims
        return F.mean(self, axis=axis, keepdims=keepdim)

    def matmul(self, other):
        return F.matmul(self, other)

    def mm(self, mat2):
        return F.matmul(self, mat2)

    def exp(self):
        return F.exp(self)

    def log(self):
        return F.log(self)

    def abs(self):
        return F.abs(self)

    def sqrt(self):
        return F.sqrt(self)

    def clamp(self, min=None, max=None):
        return F.clamp(self, min=min, max=max)

    def clip(self, min=None, max=None):
        return F.clip(self, min=min, max=max)

    def relu(self):
        return F.relu(self)

    def tanh(self):
        return F.tanh(self)

    def sigmoid(self):
        return F.sigmoid(self)

    def softmax(self, dim=None, axis=-1):
        return F.softmax(self, axis=axis, dim=dim)

    def log_softmax(self, dim=None, axis=-1):
        return F.log_softmax(self, axis=axis, dim=dim)

    def argmax(self, dim=None, keepdim=False, axis=None, keepdims=None):
        return F.argmax(self, dim=dim, keepdim=keepdim, axis=axis,
                        keepdims=keepdims)

    def topk(self, k, dim=None, largest=True, sorted=True):
        return F.topk(self, k, dim=dim, largest=largest, sorted=sorted)

    def masked_fill(self, mask, value):
        return F.masked_fill(self, mask, value)

    def nonzero(self, as_tuple=False):
        return F.nonzero(self, as_tuple=as_tuple)

    def index_select(self, dim, index):
        return F.index_select(self, dim, index)

    def gather(self, dim, index):
        return F.gather(self, dim, index)

    def scatter(self, dim, index, src):
        return F.scatter(self, dim, index, src)

    def scatter_add(self, dim, index, src):
        return F.scatter_add(self, dim, index, src)

    def sort(self, dim=-1, descending=False, stable=False):
        return F.sort(self, dim=dim, descending=descending, stable=stable)

    def argsort(self, dim=-1, descending=False, stable=False):
        return F.argsort(self, dim=dim, descending=descending, stable=stable)

    def max(self, dim=None, keepdim=False, axis=None, keepdims=None):
        return F.max(self, dim=dim, keepdim=keepdim, axis=axis,
                     keepdims=keepdims)

    def min(self, dim=None, keepdim=False, axis=None, keepdims=None):
        return F.min(self, dim=dim, keepdim=keepdim, axis=axis,
                     keepdims=keepdims)

    def amax(self, dim=None, keepdim=False, axis=None, keepdims=None):
        return F.amax(self, dim=dim, keepdim=keepdim, axis=axis,
                      keepdims=keepdims)

    def amin(self, dim=None, keepdim=False, axis=None, keepdims=None):
        return F.amin(self, dim=dim, keepdim=keepdim, axis=axis,
                      keepdims=keepdims)

    def aminmax(self, dim=None, keepdim=False, axis=None, keepdims=None):
        return F.aminmax(self, dim=dim, keepdim=keepdim, axis=axis,
                         keepdims=keepdims)

    def renamed(self, name):
        self.name = name
        return self

    def clone(self):
        return F.clone(self)

    def tolist(self):
        return self.numpy().tolist()

    def numpy(self):
        return backend.as_numpy(self.data)

    def to(self, *args, device=None, dtype=None):
        target_device, target_dtype = _parse_to_args(args, device, dtype)
        target_device = backend.normalize_device(target_device) or self.device
        target_dtype = np.dtype(target_dtype) if target_dtype is not None else self.dtype
        if target_device == self.device and target_dtype == self.dtype:
            return self
        requires_grad = _requires_grad_for_dtype(
            self.requires_grad, target_dtype,
        )
        if requires_grad:
            out = F.copy_to(self, target_device, target_dtype)
        else:
            data = backend.to_device(
                self.data, target_device, dtype=target_dtype,
            )
            out = Tensor(data, requires_grad=False)
        out.name = self.name
        out.log_enabled = self.log_enabled
        return out

    def detach(self):
        return Tensor(self.data, name=self.name, log_enabled=self.log_enabled,
                      requires_grad=False)

    def float(self):
        return self.to(dtype='float32')

    def long(self):
        return self.to(dtype='int64')

    def cpu(self):
        return self.to('cpu')

    def cuda(self):
        return self.to('cuda')

    @classmethod
    def _get_shape(cls, *shape):
        if len(shape) == 1 and isinstance(shape[0], (tuple,list)):
            shape = shape[0]
        return shape

    @classmethod
    def randn(self, *shape, device=None, dtype=None, requires_grad=None):
        shape = self._get_shape(shape)
        xp = backend.array_module_for_device(device)
        data = xp.random.randn(*shape)
        if dtype is not None:
            data = xp.asarray(data, dtype=dtype)
        return Tensor(data, requires_grad=requires_grad)

    @classmethod
    def zeros(self, *shape, device=None, dtype=None, requires_grad=None):
        shape = self._get_shape(shape)
        xp = backend.array_module_for_device(device)
        return Tensor(xp.zeros(shape, dtype=dtype),
                      requires_grad=requires_grad)

    @classmethod
    def ones(self, *shape, device=None, dtype=None, requires_grad=None):
        shape = self._get_shape(shape)
        xp = backend.array_module_for_device(device)
        return Tensor(xp.ones(shape, dtype=dtype),
                      requires_grad=requires_grad)

    @classmethod
    def zeros_like(self, data):
        source = data.data if isinstance(data, Tensor) else data
        xp = backend.get_array_module(source)
        requires_grad = data.requires_grad if isinstance(data, Tensor) else None
        return Tensor(xp.zeros_like(source), requires_grad=requires_grad)

    @classmethod
    def ones_like(self, data):
        source = data.data if isinstance(data, Tensor) else data
        xp = backend.get_array_module(source)
        requires_grad = data.requires_grad if isinstance(data, Tensor) else None
        return Tensor(xp.ones_like(source), requires_grad=requires_grad)

    @property
    def T(self):
        '''
        tensor.T 是 PyTorch 中对二维张量进行转置的简便方法，相当于 tensor.transpose(0, 1)。
        对于三维或更高维张量，tensor.T 不会改变张量的形状。
        '''
        return F.transpose(self)

    @property
    def shape(self):
        return self.data.shape

    @property
    def ndim(self):
        return self.data.ndim

    def dim(self):
        return self.ndim

    def numel(self):
        return int(self.data.size)

    def size(self, dim=None):
        # torch-like, 而不是self.data.size
        if dim is None:
            return self.data.shape
        else:
            return self.data.shape[dim]

    def item(self):
        assert len(self.data.shape) == 0
        #print(type(self.data))
        #print(self.data.value)
        data = self.data
        #print(type(data))
        #print(type(data.item()))
        #print(type(self.data), self.data)
        #print(repr(self.data.item()))
        return self.data.item()

    @property
    def dtype(self):
        return self.data.dtype

    @property
    def device(self):
        return backend.device_of(self.data)

    @property
    def is_cuda(self):
        return self.device == 'cuda'

    def __repr__(self):
        return (
            f'Tensor({str(self.data)}, name={self.name}'
            f', shape={self.shape}, requires_grad={self.requires_grad}'
            f', grad={self.grad})'
        ).replace('\n', '\n' + ' '*8)

    def __eq__(self, other):
        return F.eq(self, other)

    def __bool__(self):
        if self.data.size != 1:
            raise ValueError(
                'bool value of Tensor with more than one value is ambiguous'
            )
        return bool(self.item())

    def __len__(self):
        if self.ndim == 0:
            raise TypeError('len() of a 0-d tensor')
        return self.shape[0]


def register_ops():
    Tensor.__neg__ = F.neg
    Tensor.__abs__ = F.abs

    Tensor.__add__ = F.add
    Tensor.__radd__ = F.add
    Tensor.__sub__ = F.sub
    Tensor.__rsub__ = F.rsub

    Tensor.__mul__ = F.mul
    Tensor.__rmul__ = F.mul
    Tensor.__truediv__ = F.div
    Tensor.__rtruediv__ = F.rdiv

    Tensor.__pow__ = F.pow
    Tensor.__matmul__ = F.matmul
    Tensor.__getitem__ = get_item

    Tensor.__eq__ = F.eq
    Tensor.__ne__ = F.ne
    Tensor.__lt__ = F.lt
    Tensor.__le__ = F.le
    Tensor.__gt__ = F.gt
    Tensor.__ge__ = F.ge


def no_grad():
    return using_config('enable_backprop', False)

def ensure_tensor(data):
    if isinstance(data, Tensor):
        return data
    return Tensor(data, requires_grad=False)

def make_tensor(data):
    return Tensor(data)

def _is_dtype_like(value):
    if value is None or isinstance(value, (Tensor, backend.device)):
        return False
    try:
        np.dtype(value)
    except (TypeError, ValueError):
        return False
    return True

def _parse_to_args(args, device=None, dtype=None):
    if len(args) > 2:
        raise TypeError('to expected at most 2 positional arguments')
    if len(args) == 2:
        if device is not None or dtype is not None:
            raise TypeError('to got both positional and keyword targets')
        device, dtype = args
    elif len(args) == 1:
        target = args[0]
        if isinstance(target, Tensor):
            if device is None:
                device = target.device
            if dtype is None:
                dtype = target.dtype
        elif _is_dtype_like(target):
            if dtype is not None:
                raise TypeError('to got dtype twice')
            dtype = target
        else:
            if device is not None:
                raise TypeError('to got device twice')
            device = target
    return device, dtype

def _requires_grad_for_dtype(requires_grad, dtype):
    if dtype is None:
        return requires_grad
    return requires_grad and np.issubdtype(np.dtype(dtype), np.floating)

def allclose(a, b, rtol=1e-05, atol=1e-08, equal_nan=False):
    a = ensure_tensor(a)
    b = ensure_tensor(b)
    return a.shape == b.shape and np.allclose(a.numpy(), b.numpy(), rtol=rtol, atol=atol, equal_nan=equal_nan)

def _normalize_shape_args(shape):
    if len(shape) == 1 and isinstance(shape[0], (tuple, list)):
        return tuple(shape[0])
    return tuple(shape)

def rand(*shape, device=None, dtype=None, requires_grad=False):
    shape = _normalize_shape_args(shape)
    xp = backend.array_module_for_device(device)
    data = xp.random.rand(*shape)
    if dtype is not None:
        data = xp.asarray(data, dtype=dtype)
    return Tensor(data, requires_grad=requires_grad)

def randn(*shape, device=None, dtype=None, requires_grad=False):
    shape = _normalize_shape_args(shape)
    xp = backend.array_module_for_device(device)
    data = xp.random.randn(*shape)
    if dtype is not None:
        data = xp.asarray(data, dtype=dtype)
    return Tensor(data, requires_grad=requires_grad)

def _normalize_size(size):
    if isinstance(size, int):
        return (size,)
    return tuple(size)

def arange(start, end=None, step=1, device=None, dtype=None, requires_grad=False):
    if end is None:
        start, end = 0, start
    xp = backend.array_module_for_device(device)
    return Tensor(
        xp.arange(start, end, step, dtype=dtype),
        requires_grad=requires_grad,
    )

def eye(n, m=None, device=None, dtype=None, requires_grad=False):
    xp = backend.array_module_for_device(device)
    columns = n if m is None else m
    return Tensor(
        xp.eye(n, columns, dtype=dtype),
        requires_grad=requires_grad,
    )

def as_tensor(data, device=None, dtype=None):
    if isinstance(data, Tensor):
        if device is None and dtype is None:
            return data
        return data.to(device=device, dtype=dtype)
    return Tensor(data, device=device, dtype=dtype, requires_grad=False)

def from_numpy(ndarray):
    return Tensor(ndarray, requires_grad=False)

def rand_like(input, device=None, dtype=None, requires_grad=False):
    input = ensure_tensor(input)
    target_device = input.device if device is None else device
    target_dtype = input.dtype if dtype is None else dtype
    xp = backend.array_module_for_device(target_device)
    return Tensor(
        xp.asarray(xp.random.rand(*input.shape), dtype=target_dtype),
        requires_grad=requires_grad,
    )

def randn_like(input, device=None, dtype=None, requires_grad=False):
    input = ensure_tensor(input)
    target_device = input.device if device is None else device
    target_dtype = input.dtype if dtype is None else dtype
    xp = backend.array_module_for_device(target_device)
    return Tensor(
        xp.asarray(xp.random.randn(*input.shape), dtype=target_dtype),
        requires_grad=requires_grad,
    )

def randint(low, high=None, size=None, device=None, dtype=None,
            requires_grad=False):
    if size is None and isinstance(high, (tuple, list)):
        size = high
        high = low
        low = 0
    elif high is None:
        high = low
        low = 0
    if size is None:
        raise ValueError('randint requires a size')
    if dtype is None:
        dtype = np.int64
    xp = backend.array_module_for_device(device)
    data = xp.random.randint(low, high, size=_normalize_size(size))
    if dtype is not None:
        data = data.astype(dtype)
    return Tensor(data, requires_grad=requires_grad)

def zeros(*shape, device=None, dtype=None, requires_grad=False):
    return Tensor.zeros(*shape, device=device, dtype=dtype,
                        requires_grad=requires_grad)

def ones(*shape, device=None, dtype=None, requires_grad=False):
    return Tensor.ones(*shape, device=device, dtype=dtype,
                       requires_grad=requires_grad)

def zeros_like(input, device=None, dtype=None, requires_grad=False):
    data = input.data if isinstance(input, Tensor) else backend.ensure_array(input)
    target_device = input.device if isinstance(input, Tensor) and device is None else device
    target_dtype = data.dtype if dtype is None else dtype
    xp = backend.get_array_module(data) if target_device is None else backend.array_module_for_device(target_device)
    return Tensor(
        xp.zeros(data.shape, dtype=target_dtype),
        device=target_device,
        requires_grad=requires_grad,
    )

def ones_like(input, device=None, dtype=None, requires_grad=False):
    data = input.data if isinstance(input, Tensor) else backend.ensure_array(input)
    target_device = input.device if isinstance(input, Tensor) and device is None else device
    target_dtype = data.dtype if dtype is None else dtype
    xp = backend.get_array_module(data) if target_device is None else backend.array_module_for_device(target_device)
    return Tensor(
        xp.ones(data.shape, dtype=target_dtype),
        device=target_device,
        requires_grad=requires_grad,
    )

def full(size, fill_value, device=None, dtype=None, requires_grad=False):
    xp = backend.array_module_for_device(device)
    return Tensor(
        xp.full(_normalize_size(size), fill_value, dtype=dtype),
        requires_grad=requires_grad,
    )

def full_like(input, fill_value, device=None, dtype=None, requires_grad=False):
    data = input.data if isinstance(input, Tensor) else backend.ensure_array(input)
    target_device = input.device if isinstance(input, Tensor) and device is None else device
    target_dtype = data.dtype if dtype is None else dtype
    xp = backend.get_array_module(data) if target_device is None else backend.array_module_for_device(target_device)
    return Tensor(
        xp.full(data.shape, fill_value, dtype=target_dtype),
        device=target_device,
        requires_grad=requires_grad,
    )

def tensor(data, device=None, dtype=None, requires_grad=False):
    return Tensor(data, device=device, dtype=dtype,
                  requires_grad=requires_grad)

float32 = np.float32
float64 = np.float64
long = np.int64
int64 = np.int64
