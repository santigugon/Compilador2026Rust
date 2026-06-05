import torch
import triton
import triton.language as tl

@triton.jit
def _sqrt_kernel(x_ptr, out_ptr, n: tl.constexpr, BLOCK: tl.constexpr):
    pid = tl.program_id(0)
    offsets = pid * BLOCK + tl.arange(0, BLOCK)
    mask = offsets < n
    x = tl.load(x_ptr + offsets, mask=mask, other=0.0)
    y = tl.sqrt(x)
    tl.store(out_ptr + offsets, y, mask=mask)

def sqrt(input, *, out=None):
    if out is None:
        out = torch.empty_like(input)
    else:
        if out.shape != input.shape:
            raise ValueError("Output tensor must have the same shape as input tensor")
    
    n = input.numel()
    block = 256
    grid = (triton.cdiv(n, block),)
    _sqrt_kernel[grid](input, out, n, BLOCK=block)
    return out

##################################################################################################################################################



import torch

def test_sqrt():
    results = {}

    # Test case 1: Simple positive numbers
    input1 = torch.tensor([4.0, 9.0, 16.0], device='cuda')
    results["test_case_1"] = sqrt(input1)

    # Test case 2: Including zero
    input2 = torch.tensor([0.0, 1.0, 4.0], device='cuda')
    results["test_case_2"] = sqrt(input2)

    # Test case 3: Large numbers
    input3 = torch.tensor([1e10, 1e20, 1e30], device='cuda')
    results["test_case_3"] = sqrt(input3)

    # Test case 4: Small numbers
    input4 = torch.tensor([1e-10, 1e-20, 1e-30], device='cuda')
    results["test_case_4"] = sqrt(input4)

    return results

test_results = test_sqrt()
