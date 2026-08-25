"""
PyTorch AutoTune - legacy heuristic wrapper (see tuner.py for the v2.0
measured path). One-call setup of PyTorch's built-in training optimizations
===============================================================================
Applies AMP (mixed precision), torch.compile, fused optimizers, TF32 and
channels-last in one call. The speedup is workload-dependent: measured on an
A100, 2.6x for a compute-bound ResNet-50 step and ~1.2x (or nothing) for
small launch-bound workloads - measure on YOUR model; see the README.
"""

import torch
import torch.nn as nn
import torch.optim as optim
from torch.amp import autocast, GradScaler
import warnings
import time
import math
from typing import Optional, Dict, Any, Tuple

__version__ = "1.0.3"
__author__ = "Chinmay Shrivastava"

class AutoTune:
    """
    AutoTune: one-call setup of AMP, torch.compile, fused optimizers,
    TF32 and channels-last for a PyTorch training loop.

    These are PyTorch's own features; this class only selects and applies
    them. The result is workload-dependent - large compute-bound models
    benefit most, small launch-bound ones may see no gain. Measure.

    Example:
        >>> from pytorch_autotune import AutoTune
        >>> model = torchvision.models.resnet18()
        >>> autotune = AutoTune(model, device='cuda')
        >>> model, optimizer, scaler = autotune.optimize()
    """
    
    def __init__(
        self,
        model: nn.Module,
        device: str = 'cuda',
        batch_size: int = None,
        verbose: bool = True
    ):
        """
        Initialize AutoTune.
        
        Args:
            model: PyTorch model to optimize
            device: Device to use ('cuda' or 'cpu')
            batch_size: Batch size for training (optional, for auto-detection)
            verbose: Print optimization details
        """
        self.model = model
        self.device = device
        self.batch_size = batch_size
        self.verbose = verbose
        self.config = {}
        
        # Detect hardware capabilities
        self._detect_hardware()
        
    def _detect_hardware(self):
        """Detect hardware capabilities and set optimal config."""
        self.config['has_cuda'] = torch.cuda.is_available()
        
        if self.config['has_cuda']:
            # Get GPU info
            self.config['gpu_name'] = torch.cuda.get_device_name()
            compute_capability = torch.cuda.get_device_capability()
            self.config['compute_capability'] = compute_capability
            
            # Determine optimal settings based on GPU
            gpu_name_lower = self.config['gpu_name'].lower()
            
            # Check for specific GPU families
            if 't4' in gpu_name_lower:
                self.config['gpu_family'] = 'turing'
                self.config['use_bfloat16'] = False  # T4 doesn't support bf16 well
                self.config['use_tf32'] = False
            elif 'v100' in gpu_name_lower:
                self.config['gpu_family'] = 'volta'
                self.config['use_bfloat16'] = False
                self.config['use_tf32'] = False
            elif 'a100' in gpu_name_lower or 'a40' in gpu_name_lower:
                self.config['gpu_family'] = 'ampere'
                self.config['use_bfloat16'] = True
                self.config['use_tf32'] = True
            elif 'h100' in gpu_name_lower:
                self.config['gpu_family'] = 'hopper'
                self.config['use_bfloat16'] = True
                self.config['use_tf32'] = True
            else:
                # Generic based on compute capability
                self.config['gpu_family'] = 'unknown'
                self.config['use_bfloat16'] = compute_capability[0] >= 8
                self.config['use_tf32'] = compute_capability[0] >= 8
            
            # Check for torch.compile availability
            self.config['has_compile'] = hasattr(torch, 'compile')
            
            # Check for fused optimizer support
            self.config['supports_fused'] = compute_capability[0] >= 7
            
            if self.verbose:
                print(f"🔍 Detected: {self.config['gpu_name']}")
                print(f"   Compute capability: {compute_capability}")
                print(f"   Mixed precision: ✅ Enabled")
                if self.config['has_compile']:
                    print(f"   torch.compile: ✅ Available")
                if self.config['supports_fused']:
                    print(f"   Fused optimizers: ✅ Supported")
        else:
            if self.verbose:
                print("⚠️ No CUDA device found. Limited optimizations available.")
    
    def optimize(
        self,
        optimizer_name: str = 'AdamW',
        learning_rate: float = 0.001,
        compile_mode: str = 'default',
        use_amp: bool = None,
        use_compile: bool = None,
        use_fused: bool = None,
        use_channels_last: bool = None
    ) -> Tuple[nn.Module, Any, Optional[GradScaler]]:
        """
        Apply optimizations and return optimized model, optimizer, and scaler.
        
        Args:
            optimizer_name: Name of optimizer ('AdamW', 'Adam', 'SGD')
            learning_rate: Learning rate
            compile_mode: torch.compile mode ('default', 'reduce-overhead', 'max-autotune')
            use_amp: Use automatic mixed precision (None=auto-detect)
            use_compile: Use torch.compile (None=auto-detect)
            use_fused: Use fused optimizer (None=auto-detect)
            use_channels_last: Use channels-last memory format (None=auto-detect)
            
        Returns:
            Tuple of (optimized_model, optimizer, scaler)
        """
        
        # Auto-detect optimal settings if not specified
        if use_amp is None:
            use_amp = self.config.get('has_cuda', False)
        
        if use_compile is None:
            use_compile = self.config.get('has_compile', False)
        
        if use_fused is None:
            use_fused = self.config.get('supports_fused', False)
        
        if use_channels_last is None:
            # Use channels_last for CNNs on compatible GPUs
            use_channels_last = (
                self._is_cnn(self.model) and 
                self.config.get('has_cuda', False)
            )
        
        # Move model to device
        self.model = self.model.to(self.device)
        
        # Apply channels-last memory format if beneficial
        if use_channels_last:
            self.model = self.model.to(memory_format=torch.channels_last)
            if self.verbose:
                print("✅ Applied channels-last memory format")
        
        # Apply torch.compile if available
        if use_compile and self.config.get('has_compile', False):
            try:
                # Use safe mode to avoid CUDA graph issues
                if compile_mode == 'max-autotune':
                    self.model = torch.compile(self.model, mode='max-autotune')
                elif compile_mode == 'reduce-overhead':
                    self.model = torch.compile(self.model, mode='reduce-overhead')
                else:
                    self.model = torch.compile(self.model)
                
                if self.verbose:
                    print(f"✅ Applied torch.compile (mode={compile_mode})")
                    print("   Note: First epoch will be slower due to compilation")
            except Exception as e:
                if self.verbose:
                    print(f"⚠️ torch.compile failed: {e}")
                    print("   Continuing without compilation")
        
        # Create optimizer with fused kernels if supported
        optimizer = self._create_optimizer(
            optimizer_name, 
            learning_rate, 
            use_fused
        )
        
        # Create gradient scaler for mixed precision
        scaler = None
        if use_amp and self.config.get('has_cuda', False):
            scaler = GradScaler('cuda')
            if self.verbose:
                print("✅ Enabled automatic mixed precision (AMP)")
        
        # Enable TF32 if supported
        if self.config.get('use_tf32', False):
            torch.backends.cuda.matmul.allow_tf32 = True
            torch.backends.cudnn.allow_tf32 = True
            if self.verbose:
                print("✅ Enabled TF32 for better performance")
        
        # Set cudnn benchmark for better performance
        if self.config.get('has_cuda', False):
            torch.backends.cudnn.benchmark = True
        
        if self.verbose:
            print("\n🚀 AutoTune optimization complete!")
            print("   Speedup is workload-dependent - benchmark your own loop.")
            self._print_usage_example()
        
        return self.model, optimizer, scaler
    
    def _create_optimizer(
        self,
        optimizer_name: str,
        learning_rate: float,
        use_fused: bool
    ) -> Any:
        """Create optimizer with optional fused kernels."""
        
        params = self.model.parameters()
        
        if optimizer_name.lower() == 'adamw':
            if use_fused and self.config.get('supports_fused', False):
                try:
                    optimizer = optim.AdamW(params, lr=learning_rate, fused=True)
                    if self.verbose:
                        print(f"✅ Created fused AdamW optimizer")
                except:
                    optimizer = optim.AdamW(params, lr=learning_rate)
                    if self.verbose:
                        print(f"✅ Created AdamW optimizer (fused not available)")
            else:
                optimizer = optim.AdamW(params, lr=learning_rate)
                if self.verbose:
                    print(f"✅ Created AdamW optimizer")
                    
        elif optimizer_name.lower() == 'adam':
            if use_fused and self.config.get('supports_fused', False):
                try:
                    optimizer = optim.Adam(params, lr=learning_rate, fused=True)
                    if self.verbose:
                        print(f"✅ Created fused Adam optimizer")
                except:
                    optimizer = optim.Adam(params, lr=learning_rate)
            else:
                optimizer = optim.Adam(params, lr=learning_rate)
                if self.verbose:
                    print(f"✅ Created Adam optimizer")
                    
        elif optimizer_name.lower() == 'sgd':
            optimizer = optim.SGD(params, lr=learning_rate, momentum=0.9)
            if self.verbose:
                print(f"✅ Created SGD optimizer")
        else:
            raise ValueError(f"Unknown optimizer: {optimizer_name}")
        
        return optimizer
    
    def _is_cnn(self, model: nn.Module) -> bool:
        """Check if model is a CNN (has Conv2d layers)."""
        for module in model.modules():
            if isinstance(module, nn.Conv2d):
                return True
        return False
    
    def _print_usage_example(self):
        """Print usage example for training loop."""
        print("\n📝 Example training loop:")
        print("="*50)
        print("""
# Training with AutoTune optimizations:
for epoch in range(num_epochs):
    for batch_idx, (data, target) in enumerate(train_loader):
        data, target = data.to(device), target.to(device)
        
        optimizer.zero_grad(set_to_none=True)  # Important!
        
        if scaler is not None:  # Mixed precision
            with autocast('cuda', dtype=torch.float16):
                output = model(data)
                loss = criterion(output, target)
            scaler.scale(loss).backward()
            scaler.step(optimizer)
            scaler.update()
        else:  # Regular precision
            output = model(data)
            loss = criterion(output, target)
            loss.backward()
            optimizer.step()
""")
        print("="*50)
    
    def benchmark(
        self,
        sample_data: torch.Tensor,
        iterations: int = 100
    ) -> Dict[str, float]:
        """
        Benchmark the model to measure speedup.
        
        Args:
            sample_data: Sample input tensor
            iterations: Number of iterations to benchmark
            
        Returns:
            Dictionary with benchmark results
        """
        if self.verbose:
            print("\n⏱️ Running benchmark (forward-only, inference)...")

        data = sample_data.to(self.device)  # H2D copy outside the timed loop
        with torch.no_grad():
            for _ in range(10):  # warmup
                _ = self.model(data)

            if self.config.get('has_cuda'):
                torch.cuda.synchronize()
            start_time = time.time()
            for _ in range(iterations):
                _ = self.model(data)
            if self.config.get('has_cuda'):
                torch.cuda.synchronize()
        total_time = time.time() - start_time
        
        throughput = iterations / total_time
        ms_per_iter = (total_time / iterations) * 1000
        
        results = {
            'total_time': total_time,
            'iterations': iterations,
            'ms_per_iteration': ms_per_iter,
            'throughput': throughput
        }
        
        if self.verbose:
            print(f"   Time per iteration: {ms_per_iter:.2f}ms")
            print(f"   Throughput: {throughput:.1f} iter/sec")
        
        return results
    
    @staticmethod
    def get_optimal_batch_size(
        model: nn.Module,
        device: str = 'cuda',
        input_shape: Tuple[int, ...] = (3, 224, 224),
        min_batch: int = 1,
        max_batch: int = 512
    ) -> int:
        """
        Find optimal batch size for the model.
        
        Args:
            model: PyTorch model
            device: Device to test on
            input_shape: Shape of single input (C, H, W)
            min_batch: Minimum batch size to test
            max_batch: Maximum batch size to test
            
        Returns:
            Optimal batch size
        """
        model = model.to(device)
        optimal_batch = min_batch
        
        for batch_size in [2**i for i in range(int(math.log2(min_batch)), 
                                               int(math.log2(max_batch))+1)]:
            try:
                # Try forward and backward pass
                dummy_input = torch.randn(batch_size, *input_shape).to(device)
                output = model(dummy_input)
                if isinstance(output, torch.Tensor) and output.requires_grad:
                    output.sum().backward()
                optimal_batch = batch_size
                
                # Clear memory
                del dummy_input, output
                torch.cuda.empty_cache() if device == 'cuda' else None
                
            except RuntimeError as e:
                if "out of memory" in str(e):
                    break
                else:
                    raise e
        
        return optimal_batch

def quick_optimize(model: nn.Module, **kwargs) -> Tuple[nn.Module, Any, Optional[GradScaler]]:
    """
    One-line application of AMP + torch.compile + fused optimizer + TF32.

    Args:
        model: PyTorch model to optimize
        **kwargs: Additional arguments for AutoTune

    Returns:
        Tuple of (optimized_model, optimizer, scaler)

    Example:
        >>> model, optimizer, scaler = quick_optimize(resnet18())
    """
    autotune = AutoTune(model, **kwargs)
    return autotune.optimize()