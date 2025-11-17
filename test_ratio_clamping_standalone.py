#!/usr/bin/env python3
"""
Standalone verification script for PPO ratio clamping fix.
Runs without pytest - can be executed directly with python3.

This script validates that the log_ratio clamping change from ±20 to ±10
works correctly and prevents the overflow bug.
"""

import math
import sys


def test_overflow_prevention():
    """Test that exp(10) doesn't overflow."""
    print("Test 1: Overflow prevention...")

    try:
        import torch
    except ImportError:
        print("  ⚠ PyTorch not installed, skipping")
        return True

    max_log_ratio = 10.0
    min_log_ratio = -10.0

    # Test extreme values
    extreme_values = torch.tensor([100.0, 50.0, 20.0, 10.0, 0.0, -10.0, -20.0, -50.0, -100.0])

    # Apply clamping
    clamped = torch.clamp(extreme_values, min=min_log_ratio, max=max_log_ratio)

    # Compute exp
    ratio = torch.exp(clamped)

    # Verify all finite
    if not torch.all(torch.isfinite(ratio)):
        print("  ✗ FAILED: ratio contains inf/nan")
        return False

    # Verify bounds
    max_ratio = ratio.max().item()
    min_ratio = ratio.min().item()

    expected_max = math.exp(10.0)  # ≈ 22026
    expected_min = math.exp(-10.0)  # ≈ 4.54e-5

    if max_ratio > expected_max * 1.01:
        print(f"  ✗ FAILED: max ratio {max_ratio} exceeds expected {expected_max}")
        return False

    if min_ratio < expected_min * 0.99:
        print(f"  ✗ FAILED: min ratio {min_ratio} below expected {expected_min}")
        return False

    print(f"  ✓ PASSED: ratio ∈ [{min_ratio:.2e}, {max_ratio:.2e}]")
    return True


def test_old_bug_fixed():
    """Test that old bug (exp(20) ≈ 485M) is fixed."""
    print("Test 2: Old bug is fixed...")

    try:
        import torch
    except ImportError:
        print("  ⚠ PyTorch not installed, skipping")
        return True

    extreme_log_ratio = torch.tensor([20.0])

    # OLD (buggy): clamp to ±20
    old_clamped = torch.clamp(extreme_log_ratio, min=-20.0, max=20.0)
    old_ratio = torch.exp(old_clamped)

    # NEW (fixed): clamp to ±10
    new_clamped = torch.clamp(extreme_log_ratio, min=-10.0, max=10.0)
    new_ratio = torch.exp(new_clamped)

    old_val = old_ratio[0].item()
    new_val = new_ratio[0].item()

    # Old should be ~485M
    if old_val < 4.85e8 * 0.99:
        print(f"  ✗ FAILED: old ratio {old_val} should be ≈485M")
        return False

    # New should be ~22k
    if new_val > 23000:
        print(f"  ✗ FAILED: new ratio {new_val} should be ≈22k")
        return False

    improvement = old_val / new_val
    print(f"  ✓ PASSED: {improvement:.0f}x improvement (485M → 22k)")
    return True


def test_realistic_values():
    """Test with realistic values from training logs."""
    print("Test 3: Realistic training values...")

    try:
        import torch
    except ImportError:
        print("  ⚠ PyTorch not installed, skipping")
        return True

    # From logs: ratio_mean ≈ 1.0, ratio_std ≈ 0.03
    torch.manual_seed(42)
    log_ratio = torch.randn(1000) * 0.03  # std=0.03

    # Apply clamping
    clamped = torch.clamp(log_ratio, min=-10.0, max=10.0)
    ratio = torch.exp(clamped)

    # Check statistics
    ratio_mean = ratio.mean().item()
    ratio_std = ratio.std().item()

    if not (0.98 < ratio_mean < 1.02):
        print(f"  ✗ FAILED: ratio_mean {ratio_mean} should be ≈1.0")
        return False

    if ratio_std > 0.1:
        print(f"  ✗ FAILED: ratio_std {ratio_std} should be small")
        return False

    print(f"  ✓ PASSED: ratio_mean={ratio_mean:.3f}, ratio_std={ratio_std:.3f}")
    return True


def test_ppo_clip_interaction():
    """Test interaction with PPO clip_range."""
    print("Test 4: PPO clip interaction...")

    try:
        import torch
    except ImportError:
        print("  ⚠ PyTorch not installed, skipping")
        return True

    clip_range = 0.1

    # Various log_ratio values
    log_ratio = torch.tensor([-10.0, -1.0, 0.0, 1.0, 10.0])

    # Clamp log_ratio
    clamped = torch.clamp(log_ratio, min=-10.0, max=10.0)
    ratio = torch.exp(clamped)

    # Apply PPO clip
    ratio_clipped = torch.clamp(ratio, 1 - clip_range, 1 + clip_range)

    # Verify clipped ratios in bounds
    if not torch.all(ratio_clipped >= 0.9 - 1e-6):
        print(f"  ✗ FAILED: clipped ratio < 0.9")
        return False

    if not torch.all(ratio_clipped <= 1.1 + 1e-6):
        print(f"  ✗ FAILED: clipped ratio > 1.1")
        return False

    print(f"  ✓ PASSED: clipped ratios ∈ [0.9, 1.1]")
    return True


def test_gradient_flow():
    """Test that gradients flow correctly."""
    print("Test 5: Gradient flow...")

    try:
        import torch
    except ImportError:
        print("  ⚠ PyTorch not installed, skipping")
        return True

    log_prob = torch.tensor([0.5, 0.0, -0.5], requires_grad=True)
    old_log_prob = torch.tensor([0.0, 0.0, 0.0])
    advantages = torch.tensor([1.0, 1.0, 1.0])

    # Compute log_ratio
    log_ratio = log_prob - old_log_prob

    # Clamp
    clamped = torch.clamp(log_ratio, min=-10.0, max=10.0)
    ratio = torch.exp(clamped)

    # Loss
    loss = -(advantages * ratio).mean()

    # Backprop
    loss.backward()

    # Check gradients
    if log_prob.grad is None:
        print("  ✗ FAILED: no gradients computed")
        return False

    if not torch.all(torch.isfinite(log_prob.grad)):
        print("  ✗ FAILED: gradients are not finite")
        return False

    print(f"  ✓ PASSED: gradients are finite")
    return True


def test_actual_code_uses_correct_value():
    """Verify the actual code in distributional_ppo.py uses ±10."""
    print("Test 6: Verifying actual code uses ±10...")

    try:
        with open('/home/user/TradingBot2/distributional_ppo.py', 'r') as f:
            content = f.read()
    except FileNotFoundError:
        print("  ⚠ distributional_ppo.py not found, skipping")
        return True

    # Look for the clamping line
    if 'torch.clamp(log_ratio, min=-10.0, max=10.0)' in content:
        print("  ✓ PASSED: Code uses min=-10.0, max=10.0")
        return True
    elif 'torch.clamp(log_ratio, min=-20.0, max=20.0)' in content:
        print("  ✗ FAILED: Code still uses old values min=-20.0, max=20.0")
        return False
    else:
        print("  ⚠ WARNING: Could not find log_ratio clamping in code")
        return True


def main():
    """Run all tests."""
    print("=" * 60)
    print("PPO Ratio Clamping Fix - Validation Tests")
    print("=" * 60)
    print()

    tests = [
        test_overflow_prevention,
        test_old_bug_fixed,
        test_realistic_values,
        test_ppo_clip_interaction,
        test_gradient_flow,
        test_actual_code_uses_correct_value,
    ]

    results = []
    for test in tests:
        try:
            result = test()
            results.append(result)
        except Exception as e:
            print(f"  ✗ EXCEPTION: {e}")
            results.append(False)
        print()

    print("=" * 60)
    passed = sum(results)
    total = len(results)

    if passed == total:
        print(f"✓ ALL TESTS PASSED ({passed}/{total})")
        print("=" * 60)
        return 0
    else:
        print(f"✗ SOME TESTS FAILED ({passed}/{total} passed)")
        print("=" * 60)
        return 1


if __name__ == '__main__':
    sys.exit(main())
