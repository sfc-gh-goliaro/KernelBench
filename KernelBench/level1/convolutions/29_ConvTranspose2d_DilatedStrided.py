import os
import sys
sys.path.insert(0, os.path.dirname(os.path.dirname(os.path.abspath(__file__))))
from task_params import DISTRIBUTIONS, get_supported_distributions
import torch
import torch.nn as nn

class Model(nn.Module):
    """
    Performs a 2D transposed convolution operation with asymmetric input and square kernel, supporting dilation, padding, and stride.

    Args:
        in_channels (int): Number of channels in the input tensor.
        out_channels (int): Number of channels produced by the convolution.
        kernel_size (int): Size of the convolution kernel (square, e.g., 3 for a 3x3 kernel).
        stride (int, optional): Stride of the convolution. Defaults to 1.
        padding (int, optional): Padding applied to the input. Defaults to 0.
        dilation (int, optional): Spacing between kernel elements. Defaults to 1.
        bias (bool, optional): If `True`, adds a learnable bias to the output. Defaults to `False`.
    """
    def __init__(self, in_channels: int, out_channels: int, kernel_size: int, stride: int = 1, padding: int = 0, dilation: int = 1, bias: bool = False):
        super(Model, self).__init__()
        self.conv_transpose2d = nn.ConvTranspose2d(in_channels, out_channels, kernel_size, stride=stride, padding=padding, dilation=dilation, bias=bias)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        """
        Performs the 2D transposed convolution.

        Args:
            x (torch.Tensor): Input tensor of shape (batch_size, in_channels, height_in, width_in). 

        Returns:
            torch.Tensor: Output tensor of shape (batch_size, out_channels, height_out, width_out).
        """
        return self.conv_transpose2d(x)


# Test code

PARAMETERS = [
    {"batch_size": 16, "in_channels": 32, "out_channels": 64, "kernel_size": 3, "height_in": 64, "width_in": 128, "stride": 5, "padding": 1, "dilation": 2},
    # SDXL-VAE: dilated strided upsampling decoder
    {"batch_size": 1, "in_channels": 512, "out_channels": 256, "kernel_size": 3, "height_in": 32, "width_in": 32, "stride": 2, "padding": 1, "dilation": 1},
    # DeepLabV3: atrous spatial pyramid pooling upsampling
    {"batch_size": 4, "in_channels": 256, "out_channels": 256, "kernel_size": 3, "height_in": 65, "width_in": 65, "stride": 1, "padding": 6, "dilation": 6},
    # SegNet: encoder-decoder semantic segmentation
    {"batch_size": 8, "in_channels": 512, "out_channels": 256, "kernel_size": 3, "height_in": 28, "width_in": 28, "stride": 2, "padding": 1, "dilation": 1},
]

SUPPORTED_DISTRIBUTIONS = get_supported_distributions("convolutions", "29_ConvTranspose2d_DilatedStrided")

def get_inputs(param_idx=0, dist_name=SUPPORTED_DISTRIBUTIONS[0], dtype=torch.float32, device="cuda"):
    assert dist_name in SUPPORTED_DISTRIBUTIONS, f"Distribution {dist_name} not supported"
    assert param_idx < len(PARAMETERS), f"Parameter index {param_idx} out of range"
    p = PARAMETERS[param_idx]
    x = DISTRIBUTIONS[dist_name]((p["batch_size"], p["in_channels"], p["height_in"], p["width_in"]), dtype=dtype, device=device)
    return [x]

def get_init_inputs(param_idx=0, dist_name=None, dtype=None, device=None):
    p = PARAMETERS[param_idx]
    return [p["in_channels"], p["out_channels"], p["kernel_size"], p["stride"], p["padding"], p["dilation"]]
