import torch
import torch.nn.functional as F
import triton
import triton.language as tl
from typing import Optional, Tuple, Union
from torch import Tensor

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


def fused_lu_solve(A: Tensor, b: Tensor) -> Tensor:
    """
    Computes the solution x to Ax = b using LU decomposition.
    
    Args:
        A: The input matrix of shape (n, n).
        b: The right-hand side tensor of shape (n,).
    
    Returns:
        x: The solution tensor of shape (n,).
    """
    # Use torch.linalg.lu_factor and lu_solve for stable LU-based solve
    LU, pivots = torch.linalg.lu_factor(A)
    # b needs to be 2D for lu_solve: shape (n, 1)
    b_2d = b.unsqueeze(-1)
    x = torch.linalg.lu_solve(LU, pivots, b_2d)
    return x.squeeze(-1)

##################################################################################################################################################



def test_fused_lu_solve():
    results = {}
    
    # Test case 1: Simple 2x2 system
    A1 = torch.tensor([[3.0, 1.0], [1.0, 2.0]], device='cuda')
    b1 = torch.tensor([9.0, 8.0], device='cuda')
    results["test_case_1"] = fused_lu_solve(A1, b1)
    
    # Test case 2: 3x3 system
    A2 = torch.tensor([[1.0, 2.0, 3.0], [0.0, 1.0, 4.0], [5.0, 6.0, 0.0]], device='cuda')
    b2 = torch.tensor([6.0, 4.0, 3.0], device='cuda')
    results["test_case_2"] = fused_lu_solve(A2, b2)
    
    # Test case 3: 4x4 system
    A3 = torch.tensor([[4.0, 3.0, 2.0, 1.0], [3.0, 2.0, 1.0, 4.0], [2.0, 1.0, 4.0, 3.0], [1.0, 4.0, 3.0, 2.0]], device='cuda')
    b3 = torch.tensor([10.0, 11.0, 12.0, 13.0], device='cuda')
    results["test_case_3"] = fused_lu_solve(A3, b3)
    
    # Test case 4: Singular matrix (should raise an error)
    A4 = torch.tensor([[1.0, 2.0], [2.0, 4.0]], device='cuda')
    b4 = torch.tensor([5.0, 10.0], device='cuda')
    try:
        results["test_case_4"] = fused_lu_solve(A4, b4)
    except RuntimeError as e:
        results["test_case_4"] = str(e)
    
    return results

test_results = test_fused_lu_solve()
