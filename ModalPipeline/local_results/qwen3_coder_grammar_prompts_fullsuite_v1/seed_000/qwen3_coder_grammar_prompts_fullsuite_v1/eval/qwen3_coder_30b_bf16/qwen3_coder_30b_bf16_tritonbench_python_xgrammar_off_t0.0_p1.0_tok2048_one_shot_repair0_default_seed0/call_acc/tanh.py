import torch
import triton
import triton.language as tl

@triton.jit
def tanh_kernel(x_ptr, y_ptr, n_elements, BLOCK_SIZE: tl.constexpr):
    pid = tl.program_id(axis=0)
    block_start = pid * BLOCK_SIZE
    offsets = block_start + tl.arange(0, BLOCK_SIZE)
    mask = offsets < n_elements
    x = tl.load(x_ptr + offsets, mask=mask)
    y = tl.tanh(x)
    tl.store(y_ptr + offsets, y, mask=mask)

def tanh(input, *, out=None):
    if out is None:
        out = torch.empty_like(input)
    else:
        if out.shape != input.shape:
            raise ValueError("Output tensor must have the same shape as input tensor")
    
    n_elements = input.numel()
    BLOCK_SIZE = 1024
    grid = (triton.cdiv(n_elements, BLOCK_SIZE),)
    
    tanh_kernel[grid](input, out, n_elements, BLOCK_SIZE=BLOCK_SIZE)
    return out

##################################################################################################################################################



import torch

def test_tanh():
    results = {}

    # Test case 1: Basic test with a simple tensor
    input_tensor_1 = torch.tensor([0.0, 1.0, -1.0, 0.5, -0.5], device='cuda')
    results["test_case_1"] = tanh(input_tensor_1)

    # Test case 2: Test with a 2D tensor
    input_tensor_2 = torch.tensor([[0.0, 1.0], [-1.0, 0.5]], device='cuda')
    results["test_case_2"] = tanh(input_tensor_2)

    # Test case 3: Test with a larger tensor
    input_tensor_3 = torch.randn(100, 100, device='cuda')
    results["test_case_3"] = tanh(input_tensor_3)

    # Test case 4: Test with an empty tensor
    input_tensor_4 = torch.tensor([], device='cuda')
    results["test_case_4"] = tanh(input_tensor_4)

    return results

test_results = test_tanh()
