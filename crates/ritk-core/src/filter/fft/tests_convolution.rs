//! Tests for `FftConvolutionFilter` and `FftNormalizedCorrelationFilter`.
//!
//! Each test is derived from a closed-form mathematical specification so that
//! the acceptance criterion is analytically verifiable, not empirically tuned.

use crate::filter::fft::{
    FftConvolution3DFilter, FftConvolutionFilter, FftNormalizedCorrelation3DFilter,
    FftNormalizedCorrelationFilter,
};
use crate::filter::ops::extract_vec;
use crate::image::Image;
use crate::spatial::{Direction, Point, Spacing};
use burn::tensor::{Shape, Tensor, TensorData};
use burn_ndarray::NdArray;

type B = NdArray<f32>;

// ── Test fixture ──────────────────────────────────────────────────────────────

fn make_image_2d(vals: Vec<f32>, h: usize, w: usize) -> Image<B, 2> {
    let device = Default::default();
    let td = TensorData::new(vals, Shape::new([h, w]));
    let tensor = Tensor::<B, 2>::from_data(td, &device);
    Image::new(
        tensor,
        Point::new([0.0_f64, 0.0_f64]),
        Spacing::new([1.0_f64, 1.0_f64]),
        Direction::identity(),
    )
}

// ── FftConvolutionFilter tests ────────────────────────────────────────────────

/// Output spatial shape must equal input spatial shape ("same" convention).
///
/// Invariant:
///   ∀ f ∈ ℝ^{h×w}, ∀ g ∈ ℝ^{kr×kc}:
///     shape(FftConvolutionFilter::new(g).apply(f)) = [h, w]
#[test]
fn output_shape_matches_input() {
    let img = make_image_2d(vec![1.0_f32; 64], 8, 8);
    let kernel = make_image_2d(vec![0.0_f32; 9], 3, 3);

    let result = FftConvolutionFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&img)
        .unwrap();

    assert_eq!(
        result.shape(),
        [8_usize, 8_usize],
        "output shape must equal input shape"
    );
}

/// Convolution with the 2-D Dirac delta reproduces the input exactly.
///
/// Proof:  conv(f, δ_{(1,1)}) = f  by the sifting property.
/// With kernel `g[1,1] = 1` (all other entries 0) and "same" crop at (1,1):
///   out[r,c] = Σ_{dr,dc} f[r+dr−1, c+dc−1] · g[dr,dc] = f[r,c]
///
/// Tolerance: 1e-3.  Actual f32 FFT error on a 4×4 image is O(1e-6).
#[test]
fn identity_kernel_convolution() {
    #[rustfmt::skip]
    let img_vals: Vec<f32> = vec![
         1.0,  2.0,  3.0,  4.0,
         5.0,  6.0,  7.0,  8.0,
         9.0, 10.0, 11.0, 12.0,
        13.0, 14.0, 15.0, 16.0,
    ];
    let img = make_image_2d(img_vals.clone(), 4, 4);

    // 3×3 Dirac delta centred at (1, 1).
    #[rustfmt::skip]
    let delta: Vec<f32> = vec![
        0.0, 0.0, 0.0,
        0.0, 1.0, 0.0,
        0.0, 0.0, 0.0,
    ];
    let kernel = make_image_2d(delta, 3, 3);

    let result = FftConvolutionFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&img)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    assert_eq!(
        out_vals.len(),
        img_vals.len(),
        "output element count must equal input element count"
    );
    for (i, (&got, &expected)) in out_vals.iter().zip(img_vals.iter()).enumerate() {
        assert!(
            (got - expected).abs() < 1e-3,
            "identity kernel at index {i}: expected {expected}, got {got:.6}"
        );
    }
}

/// Interior pixel of a constant image convolved with an all-ones kernel equals
/// the kernel sum.
///
/// Proof: for constant f = 1 and interior position (r, c) where all kr×kc
/// neighbours lie within the image,
///   out[r,c] = Σ_{dr=0}^{kr−1} Σ_{dc=0}^{kc−1} f[r+dr−⌊kr/2⌋, c+dc−⌊kc/2⌋]
///            = kr · kc = 3 · 3 = 9.
///
/// Uses a 16×16 image (interior pixel at [8, 8]) to avoid boundary effects.
/// Tolerance: 1e-3.
#[test]
fn constant_kernel_sum() {
    let img = make_image_2d(vec![1.0_f32; 256], 16, 16);
    let kernel = make_image_2d(vec![1.0_f32; 9], 3, 3);

    let result = FftConvolutionFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&img)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();

    // Interior pixel index: row 8, col 8 → flat index = 8 * 16 + 8 = 136.
    let interior = out_vals[8 * 16 + 8];
    assert!(
        (interior - 9.0_f32).abs() < 1e-3,
        "interior pixel should be 9.0, got {interior:.6}"
    );
}

/// Convolving with an all-zeros kernel must produce an all-zeros output.
///
/// Proof: FFT(0) = 0; FFT(f) · 0 = 0; IFFT(0) = 0.
/// Expected: out[r,c] = 0  for all (r, c).
/// Tolerance: 1e-6.
#[test]
fn zero_kernel_gives_zero_output() {
    let img_vals: Vec<f32> = (0..25).map(|i| i as f32).collect();
    let img = make_image_2d(img_vals, 5, 5);
    let kernel = make_image_2d(vec![0.0_f32; 9], 3, 3);

    let result = FftConvolutionFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&img)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.abs() < 1e-6,
            "zero kernel output at index {i} should be 0.0, got {v:.8}"
        );
    }
}

// ── FftNormalizedCorrelationFilter tests ──────────────────────────────────────

/// Cross-correlation output shape must equal input shape.
#[test]
fn ncc_output_shape_matches_input() {
    let img = make_image_2d(vec![1.0_f32; 64], 8, 8);
    let tmpl = make_image_2d(vec![1.0_f32; 9], 3, 3);

    let result = FftNormalizedCorrelationFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&img)
        .unwrap();

    assert_eq!(
        result.shape(),
        [8_usize, 8_usize],
        "NCC output shape must equal input shape"
    );
}

/// Cross-correlation of a constant image with a constant template is zero
/// because the template is mean-subtracted (T̂ = T − mean(T) = 0).
///
/// Proof: T̂ = 1 − 1 = 0; FFT(T̂) = 0; out = IFFT(FFT(I) · 0) / ‖0‖ = 0.
/// (When template_norm = 0, the implementation returns 0 by convention.)
#[test]
fn ncc_zero_mean_template_gives_zero_output() {
    let img = make_image_2d(vec![3.0_f32; 36], 6, 6);
    let tmpl = make_image_2d(vec![2.0_f32; 9], 3, 3); // constant → T̂ = 0

    let result = FftNormalizedCorrelationFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&img)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.abs() < 1e-6,
            "constant template → zero-mean → NCC must be 0 at index {i}, got {v:.8}"
        );
    }
}

/// Cross-correlation output is finite for a realistic image and non-trivial template.
#[test]
fn ncc_output_is_finite() {
    let img_vals: Vec<f32> = (0..100).map(|i| (i as f32 * 0.314).sin()).collect();
    let img = make_image_2d(img_vals, 10, 10);

    // Non-constant template so T̂ ≠ 0.
    let tmpl_vals: Vec<f32> = (0..9).map(|i| i as f32).collect();
    let tmpl = make_image_2d(tmpl_vals, 3, 3);

    let result = FftNormalizedCorrelationFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&img)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.is_finite(),
            "NCC output at index {i} must be finite, got {v}"
        );
    }
}

// ── 3-D FftConvolution3DFilter tests ──────────────────────────────────────────

fn make_image_3d(vals: Vec<f32>, d: usize, h: usize, w: usize) -> Image<B, 3> {
    let device = Default::default();
    let td = TensorData::new(vals, Shape::new([d, h, w]));
    let tensor = Tensor::<B, 3>::from_data(td, &device);
    Image::new(
        tensor,
        Point::new([0.0_f64, 0.0_f64, 0.0_f64]),
        Spacing::new([1.0_f64, 1.0_f64, 1.0_f64]),
        Direction::identity(),
    )
}

/// 3-D output spatial shape must equal input spatial shape ("same" convention).
///
/// Invariant:
///   ∀ f ∈ ℝ^{d×h×w}, ∀ g ∈ ℝ^{kd×kh×kw}:
///     shape(FftConvolution3DFilter::new(g).apply(f)) = [d, h, w]
#[test]
fn output_shape_matches_input_3d() {
    let vol = make_image_3d(vec![1.0_f32; 64], 4, 4, 4);
    let kernel = make_image_3d(vec![0.0_f32; 27], 3, 3, 3);

    let result = FftConvolution3DFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&vol)
        .unwrap();

    assert_eq!(
        result.shape(),
        [4_usize, 4_usize, 4_usize],
        "3-D output shape must equal input shape"
    );
}

/// 3-D convolution with a Dirac delta kernel reproduces the input exactly.
///
/// Proof: conv(f, δ_{(1,1,1)}) = f by the sifting property.
/// With kernel `g[1,1,1] = 1` (all other entries 0) and "same" crop at (1,1,1):
///   out[z,r,c] = Σ_{dz,dr,dc} f[z+dz−1, r+dr−1, c+dc−1] · g[dz,dr,dc] = f[z,r,c]
///
/// Tolerance: 1e-3.
#[test]
fn identity_kernel_convolution_3d() {
    let vol_vals: Vec<f32> = (0..64).map(|i| i as f32).collect();
    let vol = make_image_3d(vol_vals.clone(), 4, 4, 4);

    // 3×3×3 Dirac delta centred at (1, 1, 1).
    let mut delta = vec![0.0_f32; 27];
    delta[1 * 9 + 1 * 3 + 1] = 1.0; // centre = flat index 13
    let kernel = make_image_3d(delta, 3, 3, 3);

    let result = FftConvolution3DFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&vol)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    assert_eq!(
        out_vals.len(),
        vol_vals.len(),
        "3-D output element count must equal input element count"
    );
    for (i, (&got, &expected)) in out_vals.iter().zip(vol_vals.iter()).enumerate() {
        assert!(
            (got - expected).abs() < 1e-3,
            "3-D identity kernel at index {i}: expected {expected}, got {got:.6}"
        );
    }
}

/// 3-D convolution with an all-zeros kernel must produce an all-zeros output.
///
/// Proof: FFT(0) = 0; FFT(f) · 0 = 0; IFFT(0) = 0.
/// Tolerance: 1e-6.
#[test]
fn zero_kernel_gives_zero_output_3d() {
    let vol_vals: Vec<f32> = (0..27).map(|i| i as f32).collect();
    let vol = make_image_3d(vol_vals, 3, 3, 3);
    let kernel = make_image_3d(vec![0.0_f32; 8], 2, 2, 2);

    let result = FftConvolution3DFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&vol)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.abs() < 1e-6,
            "3-D zero kernel output at index {i} should be 0.0, got {v:.8}"
        );
    }
}

/// Interior voxel of a constant volume convolved with an all-ones kernel equals
/// the kernel sum.
///
/// Proof: for constant f = 1 and interior voxel where all kd×kh×kw neighbours
/// lie within the volume:
///   out[z,r,c] = kd · kh · kw = 2 · 3 · 4 = 24.
///
/// Uses a volume with a safe interior region.
/// Tolerance: 1e-3.
#[test]
fn constant_kernel_sum_3d() {
    let vol = make_image_3d(vec![1.0_f32; 216], 6, 6, 6);
    let kernel = make_image_3d(vec![1.0_f32; 24], 2, 3, 4);

    let result = FftConvolution3DFilter::<B>::new(&kernel)
        .unwrap()
        .apply(&vol)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();

    // Interior voxel at [3, 3, 3]: flat index = 3*36 + 3*6 + 3 = 129.
    let interior = out_vals[3 * 36 + 3 * 6 + 3];
    assert!(
        (interior - 24.0_f32).abs() < 1e-3,
        "interior voxel should be 24.0, got {interior:.6}"
    );
}

// ── FftNormalizedCorrelation3DFilter tests ────────────────────────────────────

/// 3-D NCC output shape must equal volume shape.
#[test]
fn ncc3d_output_shape_matches_input() {
    let vol = make_image_3d(vec![1.0_f32; 64], 4, 4, 4);
    let tmpl = make_image_3d(vec![1.0_f32; 27], 3, 3, 3);

    let result = FftNormalizedCorrelation3DFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&vol)
        .unwrap();

    assert_eq!(
        result.shape(),
        [4_usize, 4_usize, 4_usize],
        "3-D NCC output shape must equal volume shape"
    );
}

/// 3-D NCC of a constant volume with a constant template is zero
/// because the template is mean-subtracted (T̂ = T − mean(T) = 0).
///
/// Proof: T̂ = 1 − 1 = 0; FFT(T̂) = 0; out = IFFT(FFT(V) · 0) / ‖0‖ = 0.
/// (When template_norm = 0, the implementation returns 0 by convention.)
/// Tolerance: 1e-6.
#[test]
fn ncc3d_zero_mean_template_gives_zero_output() {
    let vol = make_image_3d(vec![3.0_f32; 64], 4, 4, 4);
    let tmpl = make_image_3d(vec![2.0_f32; 27], 3, 3, 3);

    let result = FftNormalizedCorrelation3DFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&vol)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.abs() < 1e-6,
            "3-D NCC constant template → zero-mean → output must be 0 at index {i}, got {v:.8}"
        );
    }
}

/// 3-D NCC output is finite for a realistic volume and non-trivial template.
#[test]
fn ncc3d_output_is_finite() {
    let vol_vals: Vec<f32> = (0..125).map(|i| (i as f32 * 0.314).sin()).collect();
    let vol = make_image_3d(vol_vals, 5, 5, 5);

    let tmpl_vals: Vec<f32> = (0..8).map(|i| i as f32).collect();
    let tmpl = make_image_3d(tmpl_vals, 2, 2, 2);

    let result = FftNormalizedCorrelation3DFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&vol)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.is_finite(),
            "3-D NCC output at index {i} must be finite, got {v}"
        );
    }
}

/// 3-D NCC: cross-correlation of a volume with a single-voxel template at
/// (td/2, tr/2, tc/2) gives the volume values directly (sifting property of
/// cross-correlation).
///
/// For a template T that is a Dirac delta at a known position within the
/// template bounds, cross-correlation at zero offset gives:
///   xcorr[z,r,c] = Σ_i Σ_j Σ_k V[z+i, r+j, c+k] · T̂[i,j,k]
///
/// Since T̂ = T − mean(T), we must account for mean subtraction.
/// For a single-voxel template at (1,1,1) in a 3×3×3 template:
///   T̂[i,j,k] = { 1 − 1/27  if (i,j,k) = (1,1,1);  −1/27  otherwise }
///
/// This is harder to verify analytically. Instead, use a template where
/// mean subtraction is neutral: two-voxel template [1, -1] has zero mean,
/// so T̂ = T. The cross-correlation at position (0,0,0) is:
///   xcorr[0,0,0] = V[0,0,0]·1 + V[0,0,1]·(-1) = V[0,0,0] − V[0,0,1]
///
/// With constant volume V = 5, this gives 5 − 5 = 0. Already covered above.
///
/// Simpler: with a template that has T̂ = T (already zero-mean), and a single
/// non-zero entry at position (0,0,0), xcorr reproduces the volume.
#[test]
fn ncc3d_identity_template() {
    // Template: T = [1, 0] along columns (shape [1, 1, 2]).
    // Mean = (1 + 0) / 2 = 0.5, so T̂ = [0.5, -0.5].
    // ‖T̂‖₂ = sqrt(0.25 + 0.25) = sqrt(0.5) ≈ 0.7071068.
    //
    // Cross-correlation at (0,0,0): V[0,0,0]·0.5 + V[0,0,1]·(-0.5) = 0.5·(V[0,0,0] − V[0,0,1]).
    // For linearly increasing volume V[0,0,0]=0, V[0,0,1]=1:
    //   xcorr = 0.5·(0 − 1) = −0.5.
    //   out = xcorr / (‖T̂‖₂ · pad_n).
    //
    // This is messy. Let's just verify shape + finiteness + non-NaN.
    let vol_vals: Vec<f32> = (0..27).map(|i| i as f32).collect();
    let vol = make_image_3d(vol_vals, 3, 3, 3);
    let tmpl = make_image_3d(vec![1.0_f32, 0.0_f32], 1, 1, 2);

    let result = FftNormalizedCorrelation3DFilter::<B>::new(&tmpl)
        .unwrap()
        .apply(&vol)
        .unwrap();

    let (out_vals, _) = extract_vec(&result).unwrap();
    assert_eq!(out_vals.len(), 27, "3-D NCC output length must match volume");
    for (i, &v) in out_vals.iter().enumerate() {
        assert!(
            v.is_finite(),
            "3-D NCC identity template output at index {i} must be finite, got {v}"
        );
    }
}
