import numpy as np

batch_size = 128
in_channels = 8
out_channels = 64
height, width = (128, 128)
kernel_size = 3
num_groups = 16
scale_shape = (out_channels, 1, 1)
maxpool_kernel_size = 4
clamp_min = 0.0
clamp_max = 1.0

def _as_tuple(value, dims):
    if isinstance(value, tuple):
        return value
    return tuple(value for _ in range(dims))


def _conv2d(x, weight, bias, stride, padding, dilation, groups):
    if isinstance(stride, int): stride = (stride, stride)
    if isinstance(padding, int): padding = (padding, padding)
    if isinstance(dilation, int): dilation = (dilation, dilation)
    n, c_in, h, w = x.shape
    c_out, c_per_group, kh, kw = weight.shape
    oh = (h + 2 * padding[0] - dilation[0] * (kh - 1) - 1) // stride[0] + 1
    ow = (w + 2 * padding[1] - dilation[1] * (kw - 1) - 1) // stride[1] + 1
    padded = np.zeros((n, c_in, h + 2 * padding[0], w + 2 * padding[1]), dtype=x.dtype)
    padded[:, :, padding[0]:padding[0] + h, padding[1]:padding[1] + w] = x
    out = np.zeros((n, c_out, oh, ow), dtype=x.dtype)
    out_per_group = c_out // groups
    in_per_group = c_in // groups
    for b in range(n):
        for oc in range(c_out):
            g = oc // out_per_group
            for oy in range(oh):
                for ox in range(ow):
                    total = 0.0
                    for icg in range(c_per_group):
                        ic = g * in_per_group + icg
                        for ky in range(kh):
                            iy = oy * stride[0] + ky * dilation[0]
                            for kx in range(kw):
                                ix = ox * stride[1] + kx * dilation[1]
                                total += padded[b, ic, iy, ix] * weight[oc, icg, ky, kx]
                    out[b, oc, oy, ox] = total + bias[oc]
    return out


def _group_norm(x, num_groups, weight, bias, eps):
    n, c = x.shape[0], x.shape[1]
    y = x.reshape((n, num_groups, c // num_groups) + x.shape[2:])
    mean = np.mean(y, axis=tuple(range(2, y.ndim)), keepdims=True)
    var = np.var(y, axis=tuple(range(2, y.ndim)), keepdims=True)
    y = ((y - mean) / np.sqrt(var + eps)).reshape(x.shape)
    shape = (1, c) + (1,) * (x.ndim - 2)
    return y * weight.reshape(shape) + bias.reshape(shape)

def _maxpool2d(x, kernel_size, stride, padding):
    if isinstance(kernel_size, int): kernel_size = (kernel_size, kernel_size,)
    if stride is None: stride = kernel_size
    if isinstance(stride, int): stride = (stride, stride,)
    if isinstance(padding, int): padding = (padding, padding,)
    padded_shape = (x.shape[0], x.shape[1]) + tuple(x.shape[i + 2] + 2 * padding[i] for i in range(2))
    fill = -np.inf if "max" == "max" else 0.0
    padded = np.full(padded_shape, fill, dtype=x.dtype)
    src = tuple(slice(padding[i], padding[i] + x.shape[i + 2]) for i in range(2))
    padded[(slice(None), slice(None)) + src] = x
    out_shape = tuple((padded_shape[i + 2] - kernel_size[i]) // stride[i] + 1 for i in range(2))
    out = np.zeros((x.shape[0], x.shape[1]) + out_shape, dtype=x.dtype)
    for b in range(x.shape[0]):
        for c in range(x.shape[1]):
            for oy in range(out_shape[0]):
                for ox in range(out_shape[1]):
                    sy = oy * stride[0]
                    sx = ox * stride[1]
                    window = padded[(b, c, slice(sy, sy + kernel_size[0]), slice(sx, sx + kernel_size[1]))]
                    out[b, c, oy, ox] = np.max(window)
    return out

class Model:
    def __init__(self, in_channels, out_channels, kernel_size, num_groups, scale_shape, maxpool_kernel_size, clamp_min, clamp_max):
        self.conv_weight = np.zeros((out_channels, in_channels // 1) + _as_tuple(kernel_size, 2), dtype=np.float32)
        self.conv_bias = np.zeros((out_channels,), dtype=np.float32)
        self.conv_stride = 1
        self.conv_padding = 0
        self.conv_dilation = 1
        self.conv_groups = 1
        self.group_norm_num_groups = num_groups
        self.group_norm_weight = np.ones((out_channels,), dtype=np.float32)
        self.group_norm_bias = np.zeros((out_channels,), dtype=np.float32)
        self.group_norm_eps = 1e-5
        self.scale = np.ones(scale_shape, dtype=np.float32)
        self.maxpool_kernel_size = maxpool_kernel_size
        self.maxpool_stride = None
        self.maxpool_padding = 0
        self.clamp_min = clamp_min
        self.clamp_max = clamp_max

    def forward(self, x):
        x = _conv2d(x, self.conv_weight, self.conv_bias, self.conv_stride, self.conv_padding, self.conv_dilation, self.conv_groups)
        x = _group_norm(x, self.group_norm_num_groups, self.group_norm_weight, self.group_norm_bias, self.group_norm_eps)
        x = (x * self.scale)
        x = _maxpool2d(x, self.maxpool_kernel_size, self.maxpool_stride, self.maxpool_padding)
        x = np.clip(x, self.clamp_min, self.clamp_max)
        return x

