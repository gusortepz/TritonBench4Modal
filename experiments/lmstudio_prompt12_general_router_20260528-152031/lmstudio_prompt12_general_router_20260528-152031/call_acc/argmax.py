import torch
import torch.nn.functional as F
import triton
import triton.language as tl
from typing import Optional, Tuple, Union

torch.backends.cudnn.benchmark = True
torch.backends.cuda.matmul.allow_tf32 = True
torch.backends.cudnn.allow_tf32 = True
try:
    torch.set_float32_matmul_precision("high")
except Exception:
    pass
try:
    import torch._dynamo
    torch._dynamo.config.suppress_errors = True
except Exception:
    pass


def argmax(input: torch.Tensor, dim: Optional[int] = None, keepdim: bool = False) -> torch.Tensor:
    return torch.argmax(input, dim=dim, keepdim=keepdim)

##################################################################################################################################################



import torch

def test_argmax():
    results = {}

    # Test case 1: 2D tensor, dim=0
    tensor_2d = torch.tensor([[1, 3, 2], [4, 0, 5]], device='cuda')
    results["test_case_1"] = argmax(tensor_2d, dim=0)

    # Test case 2: 2D tensor, dim=1
    results["test_case_2"] = argmax(tensor_2d, dim=1)

    # Test case 3: 3D tensor, dim=2
    tensor_3d = torch.tensor([[[1, 2, 3], [4, 5, 6]], [[7, 8, 9], [10, 11, 12]]], device='cuda')
    results["test_case_3"] = argmax(tensor_3d, dim=2)

    # Test case 4: 3D tensor, dim=1, keepdim=True
    results["test_case_4"] = argmax(tensor_3d, dim=1, keepdim=True)

    return results

test_results = test_argmax()
