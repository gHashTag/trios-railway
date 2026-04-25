//! # GF16 Benchmark Tests — Replicating BENCH-001 through BENCH-006
//!
//! This test suite validates the GoldenFloat16 implementation against the whitepaper benchmarks.
//!
//! ## BENCHMARK COVERAGE
//!
//! | Bench | Description | Status |
//! |-------|-------------|--------|
//! | BENCH-001 | Quantization error (MSE/MAE) vs fp16/bf16/f32 | 🔜 |
//! | BENCH-002 | Arithmetic throughput (add/mul/div) on CPU | 🔜 |
//! | BENCH-003 | NN inference on frozen synthetic weights | 🔜 |
//! | BENCH-004a | NN inference on random weights | 🔜 |
//! | BENCH-004b | NN inference on trained MNIST MLP | 🔜 |
//! | BENCH-005 | FPGA synthesis unit-level | 📋 (requires Yosys) |
//! | BENCH-006 | FPGA synthesis MAC-level | 📋 (requires Yosys) |
//!
//! ## WHITEPAPER RESULTS (for validation)
//!
//! - **BENCH-001**: GF16 ≈ fp16, 2× better than bf16
//! - **BENCH-002**: GF16 add: 7.2 ns/op (15% faster than soft-fp16)
//! - **BENCH-003**: GF16: 5.80% (identical to f32 on synthetic)
//! - **BENCH-004a**: GF16: 11.86% (matches f32 within quantization noise)
//! - **BENCH-004b**: GF16: 97.67% = f32 (0.00% gap), bf16/ternary: catastrophic
//! - **BENCH-005**: GF16: 118 LUT add, 94 LUT + 1 DSP mul vs ternary: 2 LUT each
//! - **BENCH-006**: GF16: 71 LUT + 16 DSP vs ternary: 52 LUT + 0 DSP

#![cfg(test)]

use trios_golden_float::{GF16, hybrid};

// ============================================================================
// BENCH-001: Quantization Error Tests
// ============================================================================

/// Test quantization error compared to baseline f32.
///
/// Validates that GF16 preserves f32 precision within acceptable bounds.
#[test]
#[cfg(has_zig_lib)]
#[ignore = "requires trained weights for MSE/MAE calculation"]
fn bench_001_quantization_error() {
    // Reference values from whitepaper BENCH-001
    let phi = 1.618_034_f32;

    // Test φ encoding/decoding roundtrip
    let encoded = GF16::from_f32(phi);
    let decoded = encoded.to_f32();

    // Whitepaper claims GF16 ≈ fp16 quantization error
    let error = (decoded - phi).abs();
    assert!(
        error < 0.01,
        "BENCH-001: GF16 quantization error too large: {}",
        error
    );

    // Test edge cases
    let test_values = [
        0.0f32,            // Zero
        1.0f32,            // One
        -1.0f32,           // Negative one
        phi,                // Golden ratio
        0.5f32,            // Half
        2.0f32,            // Two
        0.618_f32,          // 1/φ
        1.0 / 1.618_034_f32, // φ reciprocal
    ];

    for &value in &test_values {
        let g = GF16::from_f32(value);
        let recovered = g.to_f32();
        let relative_error = ((recovered - value).abs() / value.abs().max(0.001));
        assert!(
            relative_error < 0.05,
            "BENCH-001: {} -> GF16 -> {}: relative error {}",
            value, recovered, relative_error
        );
    }
}

/// Test GF16 preserves precision better than bf16.
///
/// Whitepaper shows bf16 accuracy: 9.80% (-87.87% vs f32) vs GF16: 97.67% (+0.00%).
#[test]
#[cfg(has_zig_lib)]
#[ignore = "requires MNIST model and weights"]
fn bench_001_bf16_comparison() {
    // This test requires actual bf16 implementation for comparison
    // Placeholder: validate that GF16 doesn't lose critical precision

    let test_cases = vec![
        0.123_456f32,
        0.987_654f32,
        -0.555_555f32,
        1.618_034f32,
    ];

    for &value in &test_cases {
        let gf16 = GF16::from_f32(value);
        let gf16_back = gf16.to_f32();

        // GF16 should maintain at least 5 significant digits
        let digits_preserved = value.abs().log10().floor() as i32;
        assert!(
            (gf16_back - value).abs() < value.abs() * 0.001,
            "BENCH-001/bf16: {} lost significant precision: {} vs {}",
            value, gf16_back, value
        );
    }
}

// ============================================================================
// BENCH-002: Arithmetic Throughput Tests
// ============================================================================

/// Test GF16 addition performance target.
///
/// Whitepaper target: GF16 add: 7.2 ns/op (15% faster than soft-fp16).
#[test]
#[cfg(has_zig_lib)]
#[ignore = "performance benchmark — requires criterion or similar"]
fn bench_002_add_throughput() {
    let iterations = 100_000;

    let a = GF16::from_f32(1.618_034f32);
    let b = GF16::from_f32(0.618_034f32);

    let start = std::time::Instant::now();
    for _ in 0..iterations {
        let _ = a.add(b);
    }
    let duration = start.elapsed();

    // Note: This is a simplified benchmark. For accurate measurements,
    // use criterion or proptest with proper black_box.
    let ns_per_op = duration.as_nanos() as f64 / iterations as f64;

    // Whitepaper target: ~7.2 ns/op (from FFI call overhead)
    // Rust FFI adds overhead, so we measure relative improvement
    assert!(
        ns_per_op < 50.0, // Allow overhead margin
        "BENCH-002: GF16 add too slow: {} ns/op",
        ns_per_op
    );
}

/// Test GF16 multiplication correctness.
#[test]
#[cfg(has_zig_lib)]
fn bench_002_mul_correctness() {
    let test_cases = [
        (0.0f32, 0.0f32, 0.0f32),
        (1.0f32, 1.0f32, 1.0f32),
        (2.0f32, 3.0f32, 6.0f32),
        (1.618_034f32, 0.618_034f32, 1.0f32),
        (-2.0f32, 3.0f32, -6.0f32),
        (0.5f32, 0.5f32, 0.25f32),
    ];

    for (a, b, expected) in test_cases {
        let gf_a = GF16::from_f32(a);
        let gf_b = GF16::from_f32(b);
        let result = gf_a.mul(gf_b);
        let result_f32 = result.to_f32();

        let error = (result_f32 - expected).abs();
        assert!(
            error < expected.abs() * 0.01, // Allow 1% relative error
            "BENCH-002/mul: {} × {} = {} (expected {}), error = {}",
            a, b, result_f32, expected, error
        );
    }
}

/// Test GF16 division correctness.
#[test]
#[cfg(has_zig_lib)]
fn bench_002_div_correctness() {
    let test_cases = [
        (1.0f32, 2.0f32, 0.5f32),
        (1.618_034f32, 1.618_034f32, 1.0f32),
        (3.0f32, 1.5f32, 2.0f32),
        (-6.0f32, 2.0f32, -3.0f32),
    ];

    for (a, b, expected) in test_cases {
        let gf_a = GF16::from_f32(a);
        let gf_b = GF16::from_f32(b);
        let result = gf_a.div(gf_b);
        let result_f32 = result.to_f32();

        let error = (result_f32 - expected).abs();
        assert!(
            error < expected.abs() * 0.02, // Division has higher error tolerance
            "BENCH-002/div: {} ÷ {} = {} (expected {}), error = {}",
            a, b, result_f32, expected, error
        );
    }
}

/// Test that GF16 zero is preserved.
#[test]
fn bench_002_zero_preservation() {
    let zero = GF16::from_f32(0.0f32);
    let one = GF16::from_f32(1.0f32);

    let zero_add_zero = zero.add(zero);
    assert_eq!(zero_add_zero.to_f32(), 0.0f32, "0 + 0 ≠ 0");

    let zero_mul_any = zero.mul(one);
    assert_eq!(zero_mul_any.to_f32(), 0.0f32, "0 × 1 ≠ 0");

    let any_mul_zero = one.mul(zero);
    assert_eq!(any_mul_zero.to_f32(), 0.0f32, "1 × 0 ≠ 0");
}

// ============================================================================
// BENCH-003/004a: NN Inference Tests (Synthetic)
// ============================================================================

/// Test NN inference with frozen synthetic weights.
///
/// Whitepaper BENCH-003 result: GF16: 5.80% (identical to f32 on synthetic).
#[test]
#[cfg(has_zig_lib)]
#[ignore = "requires synthetic model and weights"]
fn bench_003_frozen_synthetic() {
    // Placeholder for BENCH-003
    // Should test that GF16 inference on frozen synthetic weights matches f32

    let inputs = vec![
        0.1f32, 0.5f32, 1.0f32, 1.5f32, 2.0f32,
    ];

    for &input in &inputs {
        let gf_input = GF16::from_f32(input);

        // Apply synthetic network layers
        let h1 = gf_input.mul(GF16::from_f32(0.5f32)); // First layer weight
        let h2 = h1.add(GF16::from_f32(0.1f32));    // Bias

        let output = h2.to_f32();

        // Verify no catastrophic degradation
        assert!(!output.is_nan(), "BENCH-003: NaN in output");
        assert!(!output.is_infinite(), "BENCH-003: Inf in output");
    }
}

/// Test NN inference with random initialized weights.
///
/// Whitepaper BENCH-004a result: GF16: 11.86% (matches f32 within quantization noise).
#[test]
#[cfg(has_zig_lib)]
#[ignore = "requires random-initialized model"]
fn bench_004a_random_weights() {
    // BENCH-004a tests that GF16 handles random weights correctly
    // This is important for initialization phase before training

    let mut rng = 0u32; // Simple seed for reproducibility
    let mut gf16_accuracy = 0;
    let mut f32_accuracy = 0;
    let test_samples = 100;

    for _ in 0..test_samples {
        rng = rng.wrapping_mul(1103515245).wrapping_add(12345);
        let random_val = (rng % 1000) as f32 / 1000.0f32;

        // Simulate forward pass
        let gf16_val = GF16::from_f32(random_val);
        let gf16_out = gf16_val.mul(gf16_val); // Random weight

        let f32_val = random_val;
        let f32_out = f32_val * f32_val;

        // Track "accuracy" as preserving sign and approximate magnitude
        let gf16_sign_correct = gf16_out.to_f32().signum() == (f32_out.signum());
        let f32_sign_correct = f32_out.signum() == f32_out.signum();

        if gf16_sign_correct {
            gf16_accuracy += 1;
        }
        if f32_sign_correct {
            f32_accuracy += 1;
        }
    }

    // GF16 should behave similarly to f32 on random data
    let gf16_pct = gf16_accuracy as f32 / test_samples as f32 * 100.0;
    let f32_pct = f32_accuracy as f32 / test_samples as f32 * 100.0;

    // Allow some quantization noise difference
    assert!(
        (gf16_pct - f32_pct).abs() < 20.0,
        "BENCH-004a: GF16 and f32 diverge too much on random: {} vs {}",
        gf16_pct, f32_pct
    );
}

// ============================================================================
// BENCH-004b: NN Inference on Trained MNIST MLP
// ============================================================================

/// Test MNIST MLP inference with GF16.
///
/// Whitepaper BENCH-004b result: **GF16: 97.67% = f32 (0.00% gap)**.
/// This is the critical test that proves GF16 achieves f32-equivalent accuracy.
#[test]
#[cfg(has_zig_lib)]
#[ignore = "requires trained MNIST MLP weights"]
fn bench_004b_mnist_mlp() {
    // Expected accuracies from whitepaper BENCH-004b:
    // - f32:      97.67% (baseline)
    // - fp16:     97.70% (+0.03% vs f32)
    // - bf16:      9.80%  (-87.87% vs f32) — catastrophic failure
    // - GF16:      97.67% (+0.00% vs f32) — perfect match
    // - ternary:   9.80%  (-87.87% vs f32) — catastrophic failure

    let expected_f32_accuracy = 97.67f32;
    let expected_gf16_accuracy = 97.67f32;

    // Placeholder: In a real test, we would:
    // 1. Load trained f32 weights
    // 2. Quantize to GF16
    // 3. Run inference on MNIST test set
    // 4. Compare accuracy

    // For now, verify our implementation structure supports this test
    assert_eq!(expected_f32_accuracy, expected_gf16_accuracy,
        "BENCH-004b: GF16 should match f32 accuracy (0.00% gap)");

    // When implementing, verify:
    // assert!((gf16_accuracy - f32_accuracy).abs() < 0.01,
    //     "BENCH-004b: GF16 accuracy {} differs from f32 {}",
    //     gf16_accuracy, f32_accuracy);
}

/// Test that GF16 doesn't suffer from gradient vanishing like ternary.
///
/// Whitepaper finding: Ternary cannot represent intermediate gradient values →
/// information loss accumulates. GF16's 9-bit mantissa preserves gradients.
#[test]
#[cfg(has_zig_lib)]
fn bench_004b_gradient_preservation() {
    // Simulate gradient flow through layers
    let gradients = vec![
        0.001f32,   // Small gradient
        0.01f32,    // Medium gradient
        0.1f32,     // Large gradient
        1.618_034f32, // φ-scaled gradient
    ];

    for &grad in &gradients {
        let gf16_grad = GF16::from_f32(grad);
        let recovered = gf16_grad.to_f32();

        // Small gradients should be preserved (ternary fails this)
        if grad.abs() < 0.01f32 {
            let relative_error = (recovered - grad).abs() / grad.abs();
            assert!(
                relative_error < 0.1,
                "BENCH-004b/grad: Small gradient {} lost: {} vs {}",
                grad, recovered, grad
            );
        }
    }
}

// ============================================================================
// GF16 Format Properties Tests
// ============================================================================

/// Test GF16 bit representation properties.
///
/// GF16 uses 6:9 exponent:mantissa allocation (φ-optimized).
#[test]
fn gf16_bit_representation() {
    // Test that GF16 uses 16 bits
    let test_value = 1.618_034f32;
    let _gf16 = GF16::from_f32(test_value);

    #[cfg(has_zig_lib)]
    {
        let bits = gf16.to_bits();
        assert!(bits < u16::MAX, "GF16 bits exceed u16 range");
        assert_eq!(bits.count_ones() + bits.count_zeros(), 16,
            "GF16 must be 16 bits");
    }

    // Zero should be all zeros
    let zero = GF16::from_f32(0.0f32);
    #[cfg(has_zig_lib)]
    {
        assert_eq!(zero.to_bits(), 0u16, "Zero should be 0 bits");
    }
}

/// Test GF16 range and special values.
#[test]
#[cfg(has_zig_lib)]
fn gf16_range_and_specials() {
    // Test positive range
    let max_positive = GF16::from_f32(f32::MAX / 2.0);
    let max_back = max_positive.to_f32();
    assert!(!max_back.is_infinite(), "Max value should be finite");
    assert!(!max_back.is_nan(), "Max value should not be NaN");

    // Test negative range
    let max_negative = GF16::from_f32(-f32::MAX / 2.0);
    let min_back = max_negative.to_f32();
    assert!(!min_back.is_infinite(), "Min value should be finite");

    // Test near-zero values
    let epsilon = GF16::from_f32(f32::EPSILON);
    let epsilon_back = epsilon.to_f32();
    assert!(epsilon_back > 0.0f32, "Epsilon should be positive");

    // Test denormal handling (subnormal numbers)
    let denormal = 1e-10_f32;
    let gf_denormal = GF16::from_f32(denormal);
    let denormal_back = gf_denormal.to_f32();
    // GF16 may round denormals to zero (acceptable)
    assert!(denormal_back >= 0.0f32, "Denormal handling");
}

/// Test φ-optimization of GF16.
///
/// Golden ratio φ = 1.61803398874989...
#[test]
#[cfg(has_zig_lib)]
fn gf16_phi_optimization() {
    // Verify φ constant
    let phi: f64 = 1.618_033_988_749_894_848;
    let phi_from_f32 = 1.618_034f32;

    assert!((phi - phi_from_f32 as f64).abs() < 1e-9,
        "φ constant precision");

    // Test that φ can be represented in GF16
    let gf16_phi = GF16::from_f32(phi_from_f32);
    let phi_back = gf16_phi.to_f32();

    // φ should roundtrip with <1% error
    let relative_error = (phi_back - phi_from_f32).abs() / phi_from_f32.abs();
    assert!(relative_error < 0.01,
        "GF16 φ roundtrip error: {} -> {} ({})",
        phi_from_f32, phi_back, relative_error);
}

/// Test GF16 associativity (within quantization bounds).
///
/// Floating-point is not associative, but GF16 should maintain reasonable properties.
#[test]
#[cfg(has_zig_lib)]
fn gf16_associativity() {
    let a = GF16::from_f32(1.0f32);
    let b = GF16::from_f32(2.0f32);
    let c = GF16::from_f32(3.0f32);

    let left = (a.add(b)).add(c);
    let right = a.add(b.add(c));

    let left_f32 = left.to_f32();
    let right_f32 = right.to_f32();

    let difference = (left_f32 - right_f32).abs();
    // Allow some quantization noise
    assert!(difference < 0.1f32,
        "GF16 associativity violation: {} vs {}",
        left_f32, right_f32);
}

/// Test GF16 commutativity (exact property).
#[test]
#[cfg(has_zig_lib)]
fn gf16_commutativity() {
    let test_cases = vec![
        (1.0f32, 2.0f32),
        (1.618_034f32, 0.618_034f32),
        (-1.5f32, 3.5f32),
    ];

    for (a_f32, b_f32) in test_cases {
        let a = GF16::from_f32(a_f32);
        let b = GF16::from_f32(b_f32);

        let ab = a.add(b);
        let ba = b.add(a);

        let ab_f32 = ab.to_f32();
        let ba_f32 = ba.to_f32();

        assert_eq!(ab_f32, ba_f32,
            "GF16 commutativity failed: {} ≠ {}",
            ab_f32, ba_f32);
    }
}

/// Test GF16 distributivity (within quantization bounds).
///
/// (a + b) × c should be approximately equal to a×c + b×c
#[test]
#[cfg(has_zig_lib)]
fn gf16_distributivity() {
    let a = GF16::from_f32(1.5f32);
    let b = GF16::from_f32(2.5f32);
    let c = GF16::from_f32(3.0f32);

    let left = a.add(b).mul(c);
    let right = a.mul(c).add(b.mul(c));

    let left_f32 = left.to_f32();
    let right_f32 = right.to_f32();

    let relative_error = (left_f32 - right_f32).abs() / left_f32.abs().max(0.001);
    assert!(relative_error < 0.05,
        "GF16 distributivity error: {} vs {} (rel: {})",
        left_f32, right_f32, relative_error);
}

// ============================================================================
// Dot Product Tests (BENCH-002 extension)
// ============================================================================

/// Test GF16 dot product implementation.
#[test]
#[cfg(has_zig_lib)]
fn gf16_dot_product() {
    let a: Vec<u16> = vec![
        GF16::from_f32(1.0f32).to_bits(),
        GF16::from_f32(2.0f32).to_bits(),
        GF16::from_f32(3.0f32).to_bits(),
        GF16::from_f32(0.5f32).to_bits(),
    ];

    let b: Vec<u16> = vec![
        GF16::from_f32(0.5f32).to_bits(),
        GF16::from_f32(1.0f32).to_bits(),
        GF16::from_f32(1.5f32).to_bits(),
        GF16::from_f32(2.0f32).to_bits(),
    ];

    let result = GF16::dot_product(&a, &b);
    let result_f32 = result.to_f32();

    // Expected: 1×0.5 + 2×1 + 3×1.5 + 0.5×2 = 0.5 + 2 + 4.5 + 1 = 8
    let expected = 8.0f32;
    let relative_error = (result_f32 - expected).abs() / expected;

    assert!(relative_error < 0.05,
        "GF16 dot product: {} (expected {}), error: {}",
        result_f32, expected, relative_error);
}

/// Test GF16 dot product with zero vectors.
#[test]
#[cfg(has_zig_lib)]
fn gf16_dot_product_zero() {
    let a: Vec<u16> = vec![
        GF16::from_f32(1.0f32).to_bits(),
        GF16::from_f32(2.0f32).to_bits(),
    ];

    let b: Vec<u16> = vec![0u16, 0u16];

    let result = GF16::dot_product(&a, &b);
    let result_f32 = result.to_f32();

    assert_eq!(result_f32, 0.0f32, "Dot product with zero should be zero");
}

/// Test GF16 dot product symmetry.
#[test]
#[cfg(has_zig_lib)]
fn gf16_dot_product_symmetry() {
    let a: Vec<u16> = vec![
        GF16::from_f32(1.0f32).to_bits(),
        GF16::from_f32(2.0f32).to_bits(),
    ];

    let b: Vec<u16> = vec![
        GF16::from_f32(3.0f32).to_bits(),
        GF16::from_f32(4.0f32).to_bits(),
    ];

    let ab = GF16::dot_product(&a, &b);
    let ba = GF16::dot_product(&b, &a);

    let ab_f32 = ab.to_f32();
    let ba_f32 = ba.to_f32();

    assert_eq!(ab_f32, ba_f32,
        "Dot product should be symmetric: {} ≠ {}",
        ab_f32, ba_f32);
}

// ============================================================================
// Weight Compression Tests
// ============================================================================

/// Test weight compression (f32 → GF16).
#[test]
#[cfg(has_zig_lib)]
fn gf16_compress_weights() {
    let weights = vec![
        0.1f32, 0.2f32, 0.3f32, 0.4f32, 0.5f32,
        1.618_034f32, -0.618_034f32, 0.0f32, 1.0f32, -1.0f32,
    ];

    let compressed = GF16::compress_weights(&weights);
    assert_eq!(compressed.len(), weights.len(),
        "Compressed length mismatch");

    for (i, &original) in weights.iter().enumerate() {
        let gf16 = GF16::from_bits(compressed[i]);
        let recovered = gf16.to_f32();
        let relative_error = (recovered - original).abs() / original.abs().max(0.001);
        assert!(relative_error < 0.05,
            "Weight {} compression error: {} vs {}",
            i, recovered, original);
    }
}

/// Test weight decompression (GF16 → f32).
#[test]
#[cfg(has_zig_lib)]
fn gf16_decompress_weights() {
    let original = vec![
        0.1f32, 0.2f32, 0.3f32, 0.4f32, 0.5f32,
    ];

    let compressed = GF16::compress_weights(&original);
    let decompressed = GF16::decompress_weights(&compressed);

    assert_eq!(decompressed.len(), original.len());

    for (i, &exp) in original.iter().enumerate() {
        let got = decompressed[i];
        let relative_error = (got - exp).abs() / exp.abs().max(0.001);
        assert!(relative_error < 0.05,
            "Weight {} decompression error: {} vs {}",
            i, got, exp);
    }
}

/// Test weight compression ratio.
///
/// GF16 achieves 2× compression vs f32 (16 bits vs 32 bits).
#[test]
fn gf16_compression_ratio() {
    let num_params = 1000usize;

    let f32_size = num_params * 4; // 4 bytes per f32
    let gf16_size = num_params * 2; // 2 bytes per GF16

    assert_eq!(f32_size, 4000, "f32 size calculation");
    assert_eq!(gf16_size, 2000, "GF16 size calculation");
    assert_eq!(f32_size / gf16_size, 2, "GF16 should be 2× smaller");
}

/// Test matrix quantization.
#[test]
#[cfg(has_zig_lib)]
fn gf16_quantize_matrix() {
    let data = vec![
        0.1f32, 0.2f32, 0.3f32,
        0.4f32, 0.5f32, 0.6f32,
        0.7f32, 0.8f32, 0.9f32,
    ];

    let rows = 3usize;
    let cols = 3usize;
    let scale = 1.0f32;

    let quantized = GF16::quantize_matrix(&data, rows, cols, scale);
    assert_eq!(quantized.len(), rows * cols);

    // Verify quantization preserves values
    for (i, &original) in data.iter().enumerate() {
        let gf16_val = GF16::from_bits(quantized[i]);
        let recovered = gf16_val.to_f32();
        let relative_error = (recovered - original).abs() / original.abs();
        assert!(relative_error < 0.05,
            "Matrix element {} quantization error: {} vs {}",
            i, recovered, original);
    }
}

// ============================================================================
// Helper Tests
// ============================================================================

/// Test GF16 constant zero.
#[test]
fn gf16_zero_constant() {
    let zero = GF16::from_f32(0.0f32);
    let zero_bits = zero.to_bits();
    assert_eq!(zero_bits, 0u16, "Zero should be 0 bits");
}

/// Test GF16 from bits constructor.
#[test]
fn gf16_from_bits() {
    let original = 1.618_034f32;
    let gf16 = GF16::from_f32(original);
    let bits = gf16.to_bits();
    let reconstructed = GF16::from_bits(bits);
    let recovered = reconstructed.to_f32();

    assert_eq!(bits, reconstructed.to_bits(), "Bits should roundtrip");
}

/// Test GF16 identity element for addition.
#[test]
#[ignore = "requires zig-golden-float vendor submodule"]
fn gf16_additive_identity() {
    let value = 1.618_034f32;
    let gf16_val = GF16::from_f32(value);
    let zero = GF16::from_f32(0.0f32);

    let result = gf16_val.add(zero);
    let result_f32 = result.to_f32();

    let relative_error = (result_f32 - value).abs() / value.abs();
    assert!(relative_error < 0.01,
        "Additive identity failed: {} vs {}",
        result_f32, value);
}

/// Test GF16 identity element for multiplication.
#[test]
#[ignore = "requires zig-golden-float vendor submodule"]
fn gf16_multiplicative_identity() {
    let value = 1.618_034f32;
    let gf16_val = GF16::from_f32(value);
    let one = GF16::from_f32(1.0f32);

    let result = gf16_val.mul(one);
    let result_f32 = result.to_f32();

    let relative_error = (result_f32 - value).abs() / value.abs();
    assert!(relative_error < 0.01,
        "Multiplicative identity failed: {} vs {}",
        result_f32, value);
}

/// Test GF16 multiplicative inverse.
#[test]
#[cfg(has_zig_lib)]
fn gf16_multiplicative_inverse() {
    let value = 4.0f32;
    let expected = 0.25f32;

    let gf16_val = GF16::from_f32(value);
    let one = GF16::from_f32(1.0f32);
    let inverse = one.div(gf16_val);

    let result = inverse.to_f32();
    let relative_error = (result - expected).abs() / expected;

    assert!(relative_error < 0.02,
        "Multiplicative inverse failed: {} vs {}",
        result, expected);
}
