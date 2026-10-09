//! Left/right null-space tests (#1596 split of tests.rs).

use super::*;

fn checked_spy_null(
    left: bool,
    dense: &mut impl DenseExecutor,
    input: &BoundDynamicTensorRef<'_, LateGenericSpy, f64>,
) -> Result<BoundDynFactor<LateGenericSpy, f64>, CheckedGenericFactorPlanError<LateGenericError>> {
    if left {
        left_null_dyn_checked_generic(dense, input)
    } else {
        right_null_dyn_checked_generic(dense, input)
    }
}

/// A checked Generic input whose blocks are longer on the requested null
/// side, so every coupled sector runs one QR.
fn null_side_generic_input(left: bool) -> BoundDynamicFusionMapSpace<FactorGenericRule> {
    if left {
        generic_factorization_input().0
    } else {
        wide_generic_factorization_input()
    }
}

#[test]
#[expect(
    clippy::arc_with_non_send_sync,
    reason = "the checked Generic API requires Arc identity while Cell is a single-threaded call spy"
)]
fn checked_generic_null_admits_only_after_all_dense_work_and_keeps_exact_authority() {
    // What: both null sides finish every sector QR before their output
    // admission, whose late error publishes no factor.
    for left in [true, false] {
        let source = null_side_generic_input(left);
        let data = vec![0.0; source.space().required_len().unwrap()];
        let complete_provider = Arc::new(LateGenericSpy {
            rule: FactorGenericRule,
            fail_at: usize::MAX,
            calls: Cell::new(0),
            identity: RuleIdentity::new_unique::<LateGenericSpy>(),
        });
        let complete_space = bind_to_spy(&source, &complete_provider);
        let complete_input = BoundDynamicTensorRef::try_new(&complete_space, &data).unwrap();
        let mut complete_dense = ScriptedExecutor::<CountingDense>::default();
        let factor = checked_spy_null(left, &mut complete_dense, &complete_input).unwrap();
        assert!(Arc::ptr_eq(
            factor.space().provider_arc(),
            &complete_provider
        ));
        let final_call = complete_provider.calls.get();
        assert!(final_call > 1);
        assert_eq!(complete_dense.counts().of(&[Op::Svd, Op::SvdInto]), 0);
        assert!(complete_dense.counts().qr_into > 1);

        let failing_provider = Arc::new(LateGenericSpy {
            rule: FactorGenericRule,
            fail_at: final_call,
            calls: Cell::new(0),
            identity: RuleIdentity::new_unique::<LateGenericSpy>(),
        });
        let failing_space = bind_to_spy(&source, &failing_provider);
        let failing_input = BoundDynamicTensorRef::try_new(&failing_space, &data).unwrap();
        let before = failing_input.data().to_vec();
        let mut failing_dense = ScriptedExecutor::<CountingDense>::default();
        assert!(matches!(
            checked_spy_null(left, &mut failing_dense, &failing_input),
            Err(CheckedGenericFactorPlanError::Provider(LateGenericError(call)))
                if call == final_call
        ));
        assert_eq!(
            failing_dense.counts().qr_into,
            complete_dense.counts().qr_into
        );
        assert_eq!(failing_input.data(), before);
        assert!(Arc::ptr_eq(
            failing_input.space().provider_arc(),
            &failing_provider
        ));
    }
}

#[test]
#[expect(
    clippy::arc_with_non_send_sync,
    reason = "the checked Generic API requires Arc identity while Cell is a single-threaded call spy"
)]
fn checked_generic_null_dense_failure_never_reaches_output_admission() {
    // What: a later sector QR failure stops after structural preflight and
    // before the checked output builder or any scatter can run.
    for left in [true, false] {
        let source = null_side_generic_input(left);
        let data = vec![0.0; source.space().required_len().unwrap()];
        let provider = Arc::new(LateGenericSpy {
            rule: FactorGenericRule,
            fail_at: usize::MAX,
            calls: Cell::new(0),
            identity: RuleIdentity::new_unique::<LateGenericSpy>(),
        });
        let checked = bind_to_spy(&source, &provider);
        let input = BoundDynamicTensorRef::try_new(&checked, &data).unwrap();
        let before = input.data().to_vec();
        let expected_preflight = {
            let probe = LateGenericSpy {
                rule: FactorGenericRule,
                fail_at: usize::MAX,
                calls: Cell::new(0),
                identity: RuleIdentity::new_unique::<LateGenericSpy>(),
            };
            let side = if left {
                source.space().homspace().codomain()
            } else {
                source.space().homspace().domain()
            };
            coupled_sector_block_dimensions_generic_checked(side, &probe).unwrap();
            probe.calls.get()
        };
        assert!(matches!(
            checked_spy_null(
                left,
                &mut ScriptedExecutor::<FailSecondNullQr>::default(),
                &input
            ),
            Err(CheckedGenericFactorPlanError::Operation(
                OperationError::Dense(_)
            ))
        ));
        assert_eq!(provider.calls.get(), expected_preflight);
        assert_eq!(input.data(), before);
    }
}

#[test]
#[expect(
    clippy::arc_with_non_send_sync,
    reason = "the checked Generic API requires Arc identity while Cell is a single-threaded call spy"
)]
fn checked_generic_disjoint_null_is_identity_without_dense_calls() {
    // What: disjoint support returns complete identity bases for both sides
    // and never enters dense work.
    let x = SectorId::new(1);
    let vacuum = SectorId::new(0);
    let homspace = FusionTreeHomSpace::new(
        FusionProductSpace::new([SectorLeg::new([(x, 2)], false)]),
        FusionProductSpace::new([SectorLeg::new([(vacuum, 3)], false)]),
    );
    let source = BoundDynamicFusionMapSpace::from_final_homspace_generic(
        Arc::new(FactorGenericRule),
        homspace,
    )
    .unwrap();
    let provider = Arc::new(LateGenericSpy {
        rule: FactorGenericRule,
        fail_at: usize::MAX,
        calls: Cell::new(0),
        identity: RuleIdentity::new_unique::<LateGenericSpy>(),
    });
    let checked = bind_to_spy(&source, &provider);
    let data = vec![0.0; checked.space().required_len().unwrap()];
    let input = BoundDynamicTensorRef::try_new(&checked, &data).unwrap();
    let left =
        left_null_dyn_checked_generic(&mut ScriptedExecutor::new(RejectExecutorCalls), &input)
            .unwrap();
    let right =
        right_null_dyn_checked_generic(&mut ScriptedExecutor::new(RejectExecutorCalls), &input)
            .unwrap();
    assert_eq!(left.data(), &[1.0, 0.0, 0.0, 1.0]);
    assert_eq!(right.data().len(), 9);
    for column in 0..3 {
        for row in 0..3 {
            assert_eq!(right.data()[row + 3 * column], f64::from(row == column));
        }
    }
    assert!(Arc::ptr_eq(left.space().provider_arc(), &provider));
    assert!(Arc::ptr_eq(right.space().provider_arc(), &provider));
}

#[test]
fn null_spaces_are_orthonormal_and_annihilate_the_tensor() {
    let rule = Z2FusionRule;
    let sectors = [SectorId::new(0), SectorId::new(1)];
    let degeneracy = 2usize;
    let leg = || SectorLeg::new(sectors.iter().map(|&sector| (sector, degeneracy)), false);
    let leg_dim = sectors.len() * degeneracy;

    // Tall map (2 codomain legs, 1 domain leg): nontrivial left null space.
    let tall_hom = FusionTreeHomSpace::new(
        FusionProductSpace::new([leg(), leg()]),
        FusionProductSpace::new([leg()]),
    );
    let key_count = tall_hom.fusion_tree_keys(&rule).len();
    let tall_space = FusionTensorMapSpace::from_degeneracy_shapes_coupled(
        TensorMapSpace::<2, 1>::from_dims([leg_dim, leg_dim], [leg_dim]).unwrap(),
        tall_hom,
        &rule,
        vec![vec![degeneracy; 3]; key_count],
    )
    .unwrap();
    let len = tall_space.required_len().unwrap();
    let tall = TensorMap::<f64, 2, 1>::from_vec_with_fusion_space(
        (0..len).map(|i| ((i * 3 + 1) % 13) as f64 - 6.0).collect(),
        tall_space,
    )
    .unwrap();
    let mut dense_executor = tenet_dense::DefaultDenseExecutor::new();
    let null = left_null(
        &mut dense_executor,
        &bound_tensor_ref!(Arc::new(rule), &tall),
    )
    .unwrap();

    let null_matrices = dense_sector_matrices(2, &null);
    assert!(!null_matrices.is_empty());
    assert_orthonormal_columns(&null_matrices);
    let tensor_matrices = dense_sector_matrices(2, &tall);
    for (sector, n_rows, n_cols, n) in &null_matrices {
        let (_, a_rows, a_cols, a) = tensor_matrices
            .iter()
            .find(|(candidate, ..)| candidate == sector)
            .expect("tensor sector present");
        assert_eq!(n_rows, a_rows);
        assert_eq!(*n_cols, a_rows - (*a_rows).min(*a_cols));
        // N^T A = 0.
        for null_col in 0..*n_cols {
            for a_col in 0..*a_cols {
                let mut dot = 0.0;
                for row in 0..*a_rows {
                    dot += n[row + n_rows * null_col] * a[row + a_rows * a_col];
                }
                assert!(dot.abs() < 1e-9, "left null failed: {dot}");
            }
        }
    }

    // Wide map (1 codomain leg, 2 domain legs): nontrivial right null space.
    let wide_hom = FusionTreeHomSpace::new(
        FusionProductSpace::new([leg()]),
        FusionProductSpace::new([leg(), leg()]),
    );
    let key_count = wide_hom.fusion_tree_keys(&rule).len();
    let wide_space = FusionTensorMapSpace::from_degeneracy_shapes_coupled(
        TensorMapSpace::<1, 2>::from_dims([leg_dim], [leg_dim, leg_dim]).unwrap(),
        wide_hom,
        &rule,
        vec![vec![degeneracy; 3]; key_count],
    )
    .unwrap();
    let len = wide_space.required_len().unwrap();
    let wide = TensorMap::<f64, 1, 2>::from_vec_with_fusion_space(
        (0..len).map(|i| ((i * 5 + 2) % 11) as f64 - 5.0).collect(),
        wide_space,
    )
    .unwrap();
    let null = right_null(
        &mut dense_executor,
        &bound_tensor_ref!(Arc::new(rule), &wide),
    )
    .unwrap();

    let null_matrices = dense_sector_matrices(1, &null);
    assert!(!null_matrices.is_empty());
    let tensor_matrices = dense_sector_matrices(1, &wide);
    for (sector, n_rows, n_cols, n) in &null_matrices {
        let (_, a_rows, a_cols, a) = tensor_matrices
            .iter()
            .find(|(candidate, ..)| candidate == sector)
            .expect("tensor sector present");
        assert_eq!(n_cols, a_cols);
        assert_eq!(*n_rows, a_cols - (*a_cols).min(*a_rows));
        // Rows of N are orthonormal: N N^T = I.
        for left in 0..*n_rows {
            for right in 0..*n_rows {
                let mut dot = 0.0;
                for col in 0..*n_cols {
                    dot += n[left + n_rows * col] * n[right + n_rows * col];
                }
                let expected = if left == right { 1.0 } else { 0.0 };
                assert!((dot - expected).abs() < 1e-9);
            }
        }
        // A N^T = 0 (rows of N span the kernel).
        for a_row in 0..*a_rows {
            for null_row in 0..*n_rows {
                let mut dot = 0.0;
                for col in 0..*a_cols {
                    dot += a[a_row + a_rows * col] * n[null_row + n_rows * col];
                }
                assert!(dot.abs() < 1e-9, "right null failed: {dot}");
            }
        }
    }
}

#[test]
fn square_null_spaces_are_empty_whatever_the_rank() {
    // What: the default null dimension is `(rows - cols)+` from the space
    // alone (MatrixAlgebraKit `qr_null!`/`lq_null!`), so square sectors,
    // including zero and rank-one ones, have no null directions and run no
    // dense work.
    let rule = Z2FusionRule;
    let mut dense = ScriptedExecutor::new(RejectExecutorCalls);
    for matrix in [
        one_sector_matrix(vec![0.0; 4]),
        one_sector_matrix(vec![1.0, 2.0, 1.0, 2.0]),
        one_sector_matrix(vec![1.0, 0.0, 0.0, 1.0e-300]),
    ] {
        let input = bound_tensor(Arc::new(rule), &matrix);
        let left = left_null(&mut dense, &input.as_ref()).unwrap();
        let right = right_null(&mut dense, &input.as_ref()).unwrap();
        assert_eq!(left.structure().block_count(), 0);
        assert!(left.data().is_empty());
        assert_eq!(right.structure().block_count(), 0);
        assert!(right.data().is_empty());
    }
}

/// Left null of a tall `3 x 2` and right null of a wide `2 x 3` sector in
/// dtype `D`: one null direction each, orthonormal and annihilating the
/// input under the conjugate-transpose pairing, whatever the rank.
fn assert_rectangular_null_spaces_ignore_rank<D: FactorScalar>(
    tall: Vec<D>,
    wide: Vec<D>,
    tol: f64,
) {
    let rule = Z2FusionRule;
    let mut dense = ScriptedExecutor::<CountingDense>::default();
    let tall = one_sector_rectangular_matrix(tall, 3, 2);
    let input = bound_tensor(Arc::new(rule), &tall);
    let n = left_null(&mut dense, &input.as_ref()).unwrap();
    assert_eq!(n.structure().block(0).unwrap().shape(), &[3, 1]);
    let norm: f64 = n.data().iter().map(|v| v.widen_complex().norm_sqr()).sum();
    assert!((norm - 1.0).abs() < tol);
    for col in 0..2 {
        let dot: num_complex::Complex64 = (0..3)
            .map(|row| {
                n.data()[row].widen_complex().conj() * tall.data()[row + 3 * col].widen_complex()
            })
            .sum();
        assert!(dot.norm() < tol, "left null failed: {dot}");
    }
    assert_eq!(
        right_null(&mut dense, &input.as_ref())
            .unwrap()
            .structure()
            .block_count(),
        0
    );

    let wide = one_sector_rectangular_matrix(wide, 2, 3);
    let input = bound_tensor(Arc::new(rule), &wide);
    let n = right_null(&mut dense, &input.as_ref()).unwrap();
    assert_eq!(n.structure().block(0).unwrap().shape(), &[1, 3]);
    let norm: f64 = n.data().iter().map(|v| v.widen_complex().norm_sqr()).sum();
    assert!((norm - 1.0).abs() < tol);
    for row in 0..2 {
        // A N^H = 0.
        let dot: num_complex::Complex64 = (0..3)
            .map(|col| {
                wide.data()[row + 2 * col].widen_complex() * n.data()[col].widen_complex().conj()
            })
            .sum();
        assert!(dot.norm() < tol, "right null failed: {dot}");
    }
    assert_eq!(
        left_null(&mut dense, &input.as_ref())
            .unwrap()
            .structure()
            .block_count(),
        0
    );
    assert_eq!(dense.counts().of(&[Op::Svd, Op::SvdInto]), 0);
    assert_eq!(dense.counts().qr_into, 2);
}

#[test]
fn rectangular_null_spaces_keep_the_shape_deficit_only() {
    // What: tall/wide sectors keep exactly `|rows - cols|` directions on the
    // longer side for full-rank, rank-one, near-cutoff and zero inputs, in
    // every factorization dtype; the rank deficit adds none.
    for (tall, wide) in [
        (
            vec![1.0, 2.0, 3.0, -2.0, 0.5, 1.0],
            vec![1.0, -2.0, 2.0, 0.5, 3.0, 1.0],
        ),
        (
            vec![1.0, 2.0, 3.0, 2.0, 4.0, 6.0],
            vec![1.0, 2.0, 2.0, 4.0, 3.0, 6.0],
        ),
        (
            vec![1.0, 0.0, 0.0, 0.0, 1.0e-20, 0.0],
            vec![1.0, 0.0, 0.0, 1.0e-20, 0.0, 0.0],
        ),
        (vec![0.0; 6], vec![0.0; 6]),
    ] {
        assert_rectangular_null_spaces_ignore_rank::<f64>(tall.clone(), wide.clone(), 1e-12);
        let single = |v: &Vec<f64>| v.iter().map(|&x| x as f32).collect::<Vec<_>>();
        assert_rectangular_null_spaces_ignore_rank::<f32>(single(&tall), single(&wide), 1e-5);
        // A complex payload with phases on both factors, so the pairing
        // must conjugate.
        let phased = |v: &Vec<f64>| {
            v.iter()
                .enumerate()
                .map(|(i, &x)| Complex64::new(x, 0.5 * x * (i as f64 - 2.0)))
                .collect::<Vec<_>>()
        };
        assert_rectangular_null_spaces_ignore_rank::<Complex64>(
            phased(&tall),
            phased(&wide),
            1e-12,
        );
        let phased32 = |v: &Vec<f64>| {
            phased(v)
                .into_iter()
                .map(|z| Complex32::new(z.re as f32, z.im as f32))
                .collect::<Vec<_>>()
        };
        assert_rectangular_null_spaces_ignore_rank::<Complex32>(
            phased32(&tall),
            phased32(&wide),
            1e-5,
        );
    }
}

fn assert_disjoint_null_spaces_keep_structural_directions<D: FactorScalar>() {
    let assert_identity = |data: &[D], order: usize| {
        for col in 0..order {
            for row in 0..order {
                let expected = if row == col { 1.0 } else { 0.0 };
                assert!((data[row + order * col].widen_complex().re - expected).abs() < 1e-12);
                assert!(data[row + order * col].widen_complex().im.abs() < 1e-12);
            }
        }
    };
    let provider = Arc::new(U1FusionRule);
    let tensor = u1_cross_space_map::<D>(&[(1, 2)], &[(0, 3)]);
    let input = bound_tensor(Arc::clone(&provider), &tensor);

    crate::factorize::reset_factor_buffer_build_counts_for_test();
    let left = left_null(
        &mut ScriptedExecutor::new(RejectExecutorCalls),
        &input.as_ref(),
    )
    .unwrap();
    assert_eq!(
        crate::factorize::factor_buffer_build_counts_for_test(),
        (1, 0)
    );
    assert_eq!(left.structure().block_count(), 1);
    assert_eq!(left.structure().block(0).unwrap().shape(), &[2, 2]);
    assert_eq!(left.data().len(), 4);
    assert_identity(left.data(), 2);
    assert!(Arc::ptr_eq(left.space().provider_arc(), &provider));

    crate::factorize::reset_factor_buffer_build_counts_for_test();
    let right = right_null(
        &mut ScriptedExecutor::new(RejectExecutorCalls),
        &input.as_ref(),
    )
    .unwrap();
    assert_eq!(
        crate::factorize::factor_buffer_build_counts_for_test(),
        (0, 1)
    );
    assert_eq!(right.structure().block_count(), 1);
    assert_eq!(right.structure().block(0).unwrap().shape(), &[3, 3]);
    assert_eq!(right.data().len(), 9);
    assert_identity(right.data(), 3);
    assert!(Arc::ptr_eq(right.space().provider_arc(), &provider));
}

#[test]
fn disjoint_null_spaces_keep_all_structural_directions_without_dense_work() {
    // What: a zero map between disjoint supports has the whole codomain/domain
    // as its left/right null space and builds only the requested factor.
    assert_disjoint_null_spaces_keep_structural_directions::<f64>();
    assert_disjoint_null_spaces_keep_structural_directions::<Complex64>();
}

#[test]
fn null_zero_only_input_normalizes_to_empty_without_dense_work() {
    let tensor = rectangular_svd_tensor(0, 0);
    let input = bound_tensor(Arc::new(Z2FusionRule), &tensor);
    let mut dense = ScriptedExecutor::new(RejectExecutorCalls);

    let left = left_null(&mut dense, &input.as_ref()).unwrap();
    let right = right_null(&mut dense, &input.as_ref()).unwrap();

    assert_eq!(left.structure().block_count(), 0);
    assert!(left.data().is_empty());
    assert_eq!(right.structure().block_count(), 0);
    assert!(right.data().is_empty());
}

#[test]
fn unmatched_null_sectors_coexist_with_a_full_rank_matched_sector() {
    // What: a matched square sector has no null directions and runs no
    // dense work, while side-only sectors survive as identity bases.
    let provider = Arc::new(U1FusionRule);
    let tensor = u1_cross_space_map::<f64>(&[(0, 1), (1, 2)], &[(0, 1), (2, 3)]);
    let input = bound_tensor(Arc::clone(&provider), &tensor);

    let mut dense = ScriptedExecutor::new(RejectExecutorCalls);
    let left = left_null(&mut dense, &input.as_ref()).unwrap();
    assert_eq!(left.structure().block_count(), 1);
    assert_eq!(left.structure().block(0).unwrap().shape(), &[2, 2]);

    let mut dense = ScriptedExecutor::new(RejectExecutorCalls);
    let right = right_null(&mut dense, &input.as_ref()).unwrap();
    assert_eq!(right.structure().block_count(), 1);
    assert_eq!(right.structure().block(0).unwrap().shape(), &[3, 3]);
}

#[test]
fn null_space_second_sector_failure_builds_no_factor() {
    // What: all dense work finishes before the one requested factor is built.
    let provider = Arc::new(U1FusionRule);
    let tall = u1_cross_space_map::<f64>(&[(0, 3), (1, 3)], &[(0, 2), (1, 2)]);
    let wide = u1_cross_space_map::<f64>(&[(0, 2), (1, 2)], &[(0, 3), (1, 3)]);
    for (left, tensor) in [(true, &tall), (false, &wide)] {
        let before = tensor.data().to_vec();
        let input = bound_tensor(Arc::clone(&provider), tensor);
        crate::factorize::reset_factor_buffer_build_counts_for_test();
        let mut dense = ScriptedExecutor::<FailSecondNullQr>::default();
        let result = if left {
            left_null(&mut dense, &input.as_ref())
        } else {
            right_null(&mut dense, &input.as_ref())
        };
        assert!(matches!(result, Err(OperationError::Dense(_))));
        assert_eq!(dense.counts().qr_into, 2);
        assert_eq!(
            crate::factorize::factor_buffer_build_counts_for_test(),
            (0, 0)
        );
        assert_eq!(tensor.data(), before);
    }
}

// Caller-thread allocation bytes, so a pack can be compared against its
// forced-pack control in the same process.
#[allow(unsafe_code)]
#[path = "../../../tests/support/counting_alloc.rs"]
pub(crate) mod counting_alloc;

#[global_allocator]
static ALLOCATOR: counting_alloc::CountingAllocator = counting_alloc::CountingAllocator;

/// Byte contract (#1525): per op, the forced-pack control allocates at least
/// the op's input payload more than the borrowed call, measured in-process
/// after warming both paths (provider-independent, unlike absolute budgets).
fn assert_pack_drop_covers_payload(borrowed: &[usize], packed: &[usize], payloads: &[usize]) {
    assert_eq!(borrowed.len(), payloads.len());
    assert_eq!(packed.len(), payloads.len());
    for ((&borrowed_bytes, &packed_bytes), &payload) in borrowed.iter().zip(packed).zip(payloads) {
        assert!(
            packed_bytes >= borrowed_bytes + payload,
            "borrowed {borrowed:?}, packed {packed:?}, payloads {payloads:?}"
        );
    }
}

type OutputBits = Vec<Vec<(u64, u64)>>;
type FamilyRun = (OutputBits, Vec<usize>);

fn measured_into<T>(bytes: &mut Vec<usize>, operation: impl FnOnce() -> T) -> T {
    let (value, allocs) = counting_alloc::measure(operation);
    let allocated = allocs.bytes as usize;
    bytes.push(allocated);
    value
}

fn scalar_bits<D: FactorScalar>(data: &[D]) -> Vec<(u64, u64)> {
    data.iter()
        .map(|&value| {
            let value = value.widen_complex();
            (value.re.to_bits(), value.im.to_bits())
        })
        .collect()
}

fn spectrum_bits<V: FactorScalar>(spectrum: &[SectorSpectrum<V>]) -> Vec<(u64, u64)> {
    spectrum
        .iter()
        .flat_map(|entry| scalar_bits(&entry.values))
        .collect()
}

fn element_bytes<R, D>(input: &BoundDynamicTensorRef<'_, R, D>) -> usize {
    std::mem::size_of_val(input.data())
}

/// Output bits of every multiplicity-free full, null and eigen op that borrows
/// admitted input regions; `general` must be an endomorphism.
fn multiplicity_free_full_family_bits<R, D>(
    general: &BoundDynamicTensorRef<'_, R, D>,
    tall: &BoundDynamicTensorRef<'_, R, D>,
    hermitian: &BoundDynamicTensorRef<'_, R, D>,
) -> FamilyRun
where
    R: MultiplicityFreeRigidSymbols<Scalar = f64>,
    D: FactorScalar,
{
    let mut dense = tenet_dense::DefaultDenseExecutor::new();
    let mut bits = Vec::new();
    let mut bytes = Vec::new();
    for input in [general, tall] {
        let Qr { q, r } = measured_into(&mut bytes, || qr_full_dyn(&mut dense, input).unwrap());
        bits.extend([scalar_bits(q.data()), scalar_bits(r.data())]);
        let Lq { l, q } = measured_into(&mut bytes, || lq_full_dyn(&mut dense, input).unwrap());
        bits.extend([scalar_bits(l.data()), scalar_bits(q.data())]);
        bits.push(scalar_bits(
            measured_into(&mut bytes, || left_null_dyn(&mut dense, input).unwrap()).data(),
        ));
        bits.push(scalar_bits(
            measured_into(&mut bytes, || right_null_dyn(&mut dense, input).unwrap()).data(),
        ));
    }
    let eig = measured_into(&mut bytes, || eig_full_dyn(&mut dense, general).unwrap());
    bits.extend([
        scalar_bits(eig.v().data()),
        spectrum_bits(eig.eigenvalues()),
    ]);
    let eigh = measured_into(&mut bytes, || {
        eigh_full_dyn(&mut dense, hermitian, HermitianTol::DEFAULT).unwrap()
    });
    bits.extend([
        scalar_bits(eigh.v().data()),
        spectrum_bits(eigh.eigenvalues()),
    ]);
    (bits, bytes)
}

fn multiplicity_free_tall_test_tensor<R>(rule: &R, sectors: &[SectorId]) -> TensorMap<f64, 2, 1>
where
    R: MultiplicityFreeRigidSymbols<Scalar = f64>,
{
    let degeneracy = 2usize;
    let leg = || SectorLeg::new(sectors.iter().map(|&sector| (sector, degeneracy)), false);
    let leg_dim = sectors.len() * degeneracy;
    let homspace = FusionTreeHomSpace::new(
        FusionProductSpace::new([leg(), leg()]),
        FusionProductSpace::new([leg()]),
    );
    let key_count = homspace.fusion_tree_keys(rule).len();
    let space = FusionTensorMapSpace::from_degeneracy_shapes_coupled(
        TensorMapSpace::<2, 1>::from_dims([leg_dim, leg_dim], [leg_dim]).unwrap(),
        homspace,
        rule,
        vec![vec![degeneracy; 3]; key_count],
    )
    .unwrap();
    let len = space.required_len().unwrap();
    TensorMap::<f64, 2, 1>::from_vec_with_fusion_space(
        (0..len)
            .map(|index| ((index * 13 + 7) % 31) as f64 * 0.25 - 3.5)
            .collect(),
        space,
    )
    .unwrap()
}

/// `source` in `D`; complex copies get a nonzero imaginary part unless
/// `real_only` (a Hermitian source stays Hermitian).
fn scalar_copy<D: FactorScalar, const NOUT: usize, const NIN: usize>(
    source: &TensorMap<f64, NOUT, NIN>,
    real_only: bool,
) -> TensorMap<D, NOUT, NIN> {
    TensorMap::from_vec_with_fusion_space(
        source
            .data()
            .iter()
            .enumerate()
            .map(|(index, &value)| {
                let imaginary = if real_only {
                    0.0
                } else {
                    ((index * 5 + 2) % 7) as f64 * 0.3 - 0.9
                };
                D::from_complex64(Complex64::new(value, imaginary))
            })
            .collect(),
        source.fusion_space().unwrap().as_ref().clone(),
    )
    .unwrap()
}

/// What (#1525): canonical inputs to the multiplicity-free full QR/LQ, null
/// and eigen ops pack nothing, and their outputs are bit-identical to the
/// forced-pack path; consistently reordered tilings keep the same values, and
/// mis-stacked tilings keep their factors and their eigen refusals.
fn assert_multiplicity_free_full_family_borrows_input<R, D>(rule: R, sectors: &[SectorId])
where
    R: MultiplicityFreeRigidSymbols<Scalar = f64> + Clone,
    D: FactorScalar,
{
    let provider = Arc::new(rule.clone());
    let general = scalar_copy::<D, 2, 2>(&tsvd_test_tensor(&rule, sectors), false);
    let tall = scalar_copy::<D, 2, 1>(&multiplicity_free_tall_test_tensor(&rule, sectors), false);
    let hermitian = scalar_copy::<D, 2, 2>(&hermitian_test_tensor(&rule, sectors), true);
    let bind = |tensor: &TensorMap<D, 2, 2>| bound_tensor(Arc::clone(&provider), tensor);
    let tall_bound = bound_tensor(Arc::clone(&provider), &tall);
    let tall_ref = tall_bound.as_ref();
    let tall_input = tall_ref.dynamic();

    let run = |general: &TensorMap<D, 2, 2>, hermitian: &TensorMap<D, 2, 2>| {
        let (general, hermitian) = (bind(general), bind(hermitian));
        let (general, hermitian) = (general.as_ref(), hermitian.as_ref());
        let (general, hermitian) = (general.dynamic(), hermitian.dynamic());
        let family = || multiplicity_free_full_family_bits(&general, &tall_input, &hermitian);
        // Keep the factor structures alive through both measurements. The
        // process-global caches hold them weakly, so otherwise each call
        // rebuilds them unless a concurrent test happens to hold equal ones,
        // and eigh (zero payload margin) sees that race as a byte difference.
        let _factor_plans = [&general, &tall_input, &hermitian]
            .map(|input| crate::factorize::compact_factor_plan_for_test(input.space()).unwrap());
        // Warm both paths so one-time caches do not enter the comparison.
        family();
        crate::factorize::with_forced_input_pack(family);
        crate::factorize::reset_input_pack_bytes();
        let (borrowed, borrowed_allocated) = family();
        let borrowed_bytes = crate::factorize::input_pack_bytes();
        crate::factorize::reset_input_pack_bytes();
        let (packed, packed_allocated) = crate::factorize::with_forced_input_pack(family);
        let packed_bytes = crate::factorize::input_pack_bytes();
        assert_eq!(borrowed, packed);
        let (general_bytes, tall_bytes) = (element_bytes(&general), element_bytes(&tall_input));
        // The canonical eigh already publishes through its direct region
        // path, so it packs on neither side.
        let payloads = [
            [general_bytes; 4].as_slice(),
            &[tall_bytes; 4],
            &[general_bytes, 0],
        ]
        .concat();
        (
            borrowed_bytes,
            packed_bytes,
            (borrowed_allocated, packed_allocated, payloads),
        )
    };

    // Canonical: the forced-pack control packs every call's whole input.
    let (borrowed, packed, (borrowed_allocated, packed_allocated, payloads)) =
        run(&general, &hermitian);
    assert_pack_drop_covers_payload(&borrowed_allocated, &packed_allocated, &payloads);
    assert_eq!(borrowed, 0);
    assert_eq!(packed, payloads.iter().sum::<usize>());

    // Consistently reordered tree stacking is still a tiling: same values.
    let (borrowed, _, _) = run(
        &reversed_coupled_tree_basis_copy(&rule, &general),
        &reversed_coupled_tree_basis_copy(&rule, &hermitian),
    );
    assert_eq!(borrowed, 0);

    // Mis-stacked: factors unchanged, eigen ops refused on both paths.
    let mis_stacked = bind(&mis_stacked_endomorphism_copy(&rule, &general));
    let mis_stacked_hermitian = bind(&mis_stacked_endomorphism_copy(&rule, &hermitian));
    let mis_stacked = mis_stacked.as_ref();
    let mis_stacked_hermitian = mis_stacked_hermitian.as_ref();
    let (mis_stacked, mis_stacked_hermitian) =
        (mis_stacked.dynamic(), mis_stacked_hermitian.dynamic());
    let mut dense = tenet_dense::DefaultDenseExecutor::new();
    let factor_bits = |dense: &mut tenet_dense::DefaultDenseExecutor| {
        let Qr { q, r } = qr_full_dyn(dense, &mis_stacked).unwrap();
        let Lq { l, q: lq } = lq_full_dyn(dense, &mis_stacked).unwrap();
        let left = left_null_dyn(dense, &mis_stacked).unwrap();
        let right = right_null_dyn(dense, &mis_stacked).unwrap();
        let refusal = |error: Option<OperationError>| -> Result<(), OperationError> {
            Err(error.expect("mis-stacked eigen input must be refused"))
        };
        assert_stacking_refusal(
            refusal(eig_full_dyn(dense, &mis_stacked).err()),
            "eig_full ",
        );
        assert_stacking_refusal(
            refusal(eigh_full_dyn(dense, &mis_stacked_hermitian, HermitianTol::DEFAULT).err()),
            "eigh_full ",
        );
        [
            q.data(),
            r.data(),
            l.data(),
            lq.data(),
            left.data(),
            right.data(),
        ]
        .map(scalar_bits)
    };
    let borrowed = factor_bits(&mut dense);
    let packed = crate::factorize::with_forced_input_pack(|| factor_bits(&mut dense));
    assert_eq!(borrowed, packed);
}

#[test]
fn multiplicity_free_full_null_eigen_ops_borrow_canonical_input() {
    let u1 = [-1, 0, 1].map(|charge| U1Irrep::new(charge).sector_id());
    let su2 = [0, 1].map(|twice| SU2Irrep::from_twice_spin(twice).sector_id());
    let product = product_fusion_rule(FermionParityFusionRule, U1FusionRule);
    let product_sectors = [
        product.encode_component_ids(SectorId::new(0), U1Irrep::new(0).sector_id()),
        product.encode_component_ids(SectorId::new(1), U1Irrep::new(1).sector_id()),
        product.encode_component_ids(SectorId::new(1), U1Irrep::new(-1).sector_id()),
    ];
    assert_multiplicity_free_full_family_borrows_input::<_, f64>(U1FusionRule, &u1);
    assert_multiplicity_free_full_family_borrows_input::<_, Complex64>(U1FusionRule, &u1);
    assert_multiplicity_free_full_family_borrows_input::<_, f64>(SU2FusionRule, &su2);
    assert_multiplicity_free_full_family_borrows_input::<_, Complex64>(SU2FusionRule, &su2);
    assert_multiplicity_free_full_family_borrows_input::<_, f64>(product.clone(), &product_sectors);
    assert_multiplicity_free_full_family_borrows_input::<_, Complex64>(product, &product_sectors);
}

/// Output bits of every checked-Generic full, null and eigen op that borrows
/// admitted input regions.
fn checked_full_family_bits<R, D>(
    general: &BoundDynamicTensorRef<'_, R, D>,
    tall: &BoundDynamicTensorRef<'_, R, D>,
    hermitian: &BoundDynamicTensorRef<'_, R, D>,
) -> FamilyRun
where
    R: CheckedGenericFusion,
    D: FactorScalar,
{
    let mut dense = tenet_dense::DefaultDenseExecutor::new();
    let mut bits = Vec::new();
    let mut bytes = Vec::new();
    for input in [general, tall] {
        let Qr { q, r } = measured_into(&mut bytes, || {
            qr_full_dyn_checked_generic(&mut dense, input).unwrap()
        });
        bits.extend([scalar_bits(q.data()), scalar_bits(r.data())]);
        let Lq { l, q } = measured_into(&mut bytes, || {
            lq_full_dyn_checked_generic(&mut dense, input).unwrap()
        });
        bits.extend([scalar_bits(l.data()), scalar_bits(q.data())]);
        let left = measured_into(&mut bytes, || {
            left_null_dyn_checked_generic(&mut dense, input).unwrap()
        });
        let right = measured_into(&mut bytes, || {
            right_null_dyn_checked_generic(&mut dense, input).unwrap()
        });
        bits.extend([scalar_bits(left.data()), scalar_bits(right.data())]);
    }
    let eig = measured_into(&mut bytes, || {
        eig_full_dyn_checked_generic(&mut dense, general).unwrap()
    });
    bits.extend([
        scalar_bits(eig.v().data()),
        spectrum_bits(eig.eigenvalues()),
    ]);
    let eigh = measured_into(&mut bytes, || {
        eigh_full_dyn_checked_generic(&mut dense, hermitian, HermitianTol::DEFAULT).unwrap()
    });
    bits.extend([
        scalar_bits(eigh.v().data()),
        spectrum_bits(eigh.eigenvalues()),
    ]);
    (bits, bytes)
}

#[cfg(feature = "racah-generated")]
fn su3_checked_input<D: FactorScalar>(
    provider: &Arc<tenet_core::SUNFusionRule>,
    nin: usize,
    seed: usize,
) -> (
    BoundDynamicFusionMapSpace<tenet_core::SUNFusionRule>,
    Vec<D>,
) {
    let adjoint = provider.encode_dynkin(&[1, 1]).unwrap();
    let trivial = provider.encode_dynkin(&[0, 0]).unwrap();
    let fundamental = provider.encode_dynkin(&[1, 0]).unwrap();
    let leg = || SectorLeg::new([(adjoint, 2), (trivial, 1), (fundamental, 1)], false);
    let homspace = FusionTreeHomSpace::new(
        FusionProductSpace::new([leg(), leg()]),
        FusionProductSpace::new((0..nin).map(|_| leg()).collect::<Vec<_>>()),
    );
    let space = BoundDynamicFusionMapSpace::from_final_homspace_generic_checked(
        Arc::clone(provider),
        homspace,
    )
    .unwrap();
    // Diagonal `1, 2, ..., n` plus off-diagonal entries of modulus below
    // `0.36 / n`: the Gershgorin discs (radius < 0.36) are disjoint, so every
    // square sector has distinct eigenvalues and is diagonalizable by
    // construction, independent of the dense provider.
    let mut data = vec![D::zero(); space.space().required_len().unwrap()];
    let regions = space
        .space()
        .structure()
        .coupled_sector_regions(space.space().nout())
        .unwrap()
        .unwrap();
    for region in regions.iter() {
        let rows = region.rows();
        let scale = 0.25 / rows.max(region.cols()) as f64;
        let matrix = &mut data[region.range()];
        for (index, value) in matrix.iter_mut().enumerate() {
            let (row, col) = (index % rows, index / rows);
            *value = D::from_complex64(if row == col {
                Complex64::new((row + 1) as f64, 0.0)
            } else {
                let hash = (index * 11 + seed) as f64;
                Complex64::new((hash * 0.7).sin() * scale, (hash * 1.3).cos() * scale)
            });
        }
    }
    (space, data)
}

#[cfg(feature = "racah-generated")]
fn hermitian_regions_copy<D: FactorScalar>(
    space: &BoundDynamicFusionMapSpace<tenet_core::SUNFusionRule>,
    data: &[D],
) -> Vec<D> {
    let mut hermitian = data.to_vec();
    for region in space
        .space()
        .structure()
        .coupled_sector_regions(space.space().nout())
        .unwrap()
        .unwrap()
        .iter()
    {
        let n = region.rows();
        let matrix = &data[region.range()];
        let target = &mut hermitian[region.range()];
        for col in 0..n {
            for row in 0..n {
                let value: Complex64 = (matrix[row + col * n].widen_complex()
                    + matrix[col + row * n].widen_complex().conj())
                .scale(0.5);
                target[row + col * n] = D::from_complex64(value);
            }
        }
    }
    hermitian
}

#[cfg(feature = "racah-generated")]
fn assert_checked_su3_full_family_borrows_input<D: FactorScalar>() {
    let provider = Arc::new(tenet_core::SUNFusionRule::new(3).unwrap());
    let (square, general) = su3_checked_input::<D>(&provider, 2, 3);
    let (tall_space, tall) = su3_checked_input::<D>(&provider, 1, 5);
    let hermitian = hermitian_regions_copy(&square, &general);
    assert_checked_full_family_borrows_input(
        &BoundDynamicTensorRef::try_new(&square, &general).unwrap(),
        &BoundDynamicTensorRef::try_new(&tall_space, &tall).unwrap(),
        &BoundDynamicTensorRef::try_new(&square, &hermitian).unwrap(),
    );
}

#[cfg(feature = "racah-generated")]
#[test]
fn checked_generic_full_null_eigen_ops_borrow_canonical_su3_input() {
    // Vertex multiplicity: 8 ⊗ 8 contains 8 twice.
    assert_checked_su3_full_family_borrows_input::<f64>();
    assert_checked_su3_full_family_borrows_input::<Complex64>();
}

fn assert_checked_full_family_borrows_input<R, D>(
    general: &BoundDynamicTensorRef<'_, R, D>,
    tall: &BoundDynamicTensorRef<'_, R, D>,
    hermitian: &BoundDynamicTensorRef<'_, R, D>,
) where
    R: CheckedGenericFusion,
    D: FactorScalar,
{
    let family = || checked_full_family_bits(general, tall, hermitian);
    // Warm both paths so one-time caches do not enter the comparison.
    family();
    crate::factorize::with_forced_input_pack(family);
    crate::factorize::reset_input_pack_bytes();
    let (borrowed, borrowed_allocated) = family();
    let borrowed_bytes = crate::factorize::input_pack_bytes();
    crate::factorize::reset_input_pack_bytes();
    let (packed, packed_allocated) = crate::factorize::with_forced_input_pack(family);
    let (general_bytes, tall_bytes) = (element_bytes(general), element_bytes(tall));
    let payloads = [
        [general_bytes; 4].as_slice(),
        &[tall_bytes; 4],
        &[general_bytes, element_bytes(hermitian)],
    ]
    .concat();
    assert_eq!(
        crate::factorize::input_pack_bytes(),
        payloads.iter().sum::<usize>()
    );
    assert_pack_drop_covers_payload(&borrowed_allocated, &packed_allocated, &payloads);
    assert_eq!(borrowed_bytes, 0);
    assert_eq!(borrowed, packed);
}

#[expect(
    clippy::arc_with_non_send_sync,
    reason = "the checked Generic API requires Arc identity while Cell is a single-threaded call spy"
)]
fn assert_checked_factor_generic_full_family_borrows_input<D: FactorScalar>() {
    let provider = Arc::new(LateGenericSpy {
        rule: FactorGenericRule,
        fail_at: usize::MAX,
        calls: Cell::new(0),
        identity: FactorGenericRule.rule_identity(),
    });
    let rebind = |space: &BoundDynamicFusionMapSpace<FactorGenericRule>| {
        BoundDynamicFusionMapSpace::bind_generic(space.space().clone(), Arc::clone(&provider))
            .unwrap()
    };
    let convert = |data: &[Complex64]| {
        data.iter()
            .map(|&value| D::from_complex64(value))
            .collect::<Vec<_>>()
    };
    let (square, hermitian, general) = generic_values_endomorphism_input();
    let (tall_space, tall) = generic_factorization_input();
    let (square, tall_space) = (rebind(&square), rebind(&tall_space));
    let (hermitian, general) = (convert(&hermitian), convert(&general));
    let tall = tall
        .iter()
        .enumerate()
        .map(|(index, &value)| D::from_complex64(Complex64::new(value, index as f64 * 0.125 - 0.5)))
        .collect::<Vec<_>>();
    assert_checked_full_family_borrows_input(
        &BoundDynamicTensorRef::try_new(&square, &general).unwrap(),
        &BoundDynamicTensorRef::try_new(&tall_space, &tall).unwrap(),
        &BoundDynamicTensorRef::try_new(&square, &hermitian).unwrap(),
    );
}

#[test]
fn checked_generic_full_null_eigen_ops_borrow_canonical_multiplicity_input() {
    // What (#1525): checked-Generic inputs with a two-dimensional vertex
    // space borrow their regions and keep the forced-pack values bit for bit.
    assert_checked_factor_generic_full_family_borrows_input::<f64>();
    assert_checked_factor_generic_full_family_borrows_input::<Complex64>();
}

#[test]
#[expect(
    clippy::arc_with_non_send_sync,
    reason = "the checked Generic API requires Arc identity while Cell is a single-threaded call spy"
)]
fn checked_generic_full_null_ops_keep_packing_padded_input() {
    // What: a padded tiling is not admitted, so it still packs.
    let (canonical_space, canonical_data) = generic_factorization_input();
    let (expert_space, expert_data) =
        expert_generic_factorization_input(&canonical_space, &canonical_data, true);
    let provider = Arc::new(LateGenericSpy {
        rule: FactorGenericRule,
        fail_at: usize::MAX,
        calls: Cell::new(0),
        identity: FactorGenericRule.rule_identity(),
    });
    let expert_space =
        BoundDynamicFusionMapSpace::bind_generic(expert_space.space().clone(), provider).unwrap();
    let expert = BoundDynamicTensorRef::try_new(&expert_space, &expert_data).unwrap();
    let mut dense = tenet_dense::DefaultDenseExecutor::new();
    let packed_len = canonical_data.len() * std::mem::size_of::<f64>();
    crate::factorize::reset_input_pack_bytes();
    qr_full_dyn_checked_generic(&mut dense, &expert).unwrap();
    lq_full_dyn_checked_generic(&mut dense, &expert).unwrap();
    left_null_dyn_checked_generic(&mut dense, &expert).unwrap();
    right_null_dyn_checked_generic(&mut dense, &expert).unwrap();
    assert_eq!(crate::factorize::input_pack_bytes(), 4 * packed_len);
}

#[test]
fn mf_null_factor_space_is_staged_once_per_side_and_cached() {
    // What: the multiplicity-free authority stages each null factor's space
    // exactly once, and a repeated call reuses the cached layout (the same
    // structure `Arc`).
    let tensor = rectangular_svd_tensor(5, 2);
    let bound = bound_tensor(Arc::new(Z2FusionRule), &tensor);
    let typed = bound.as_ref();
    let input = typed.dynamic();
    let mut dense = tenet_dense::DefaultDenseExecutor::new();
    let stages = || crate::factorize::MF_FACTOR_SPACE_STAGES.get();
    for left in [true, false] {
        let null = |dense: &mut tenet_dense::DefaultDenseExecutor| {
            if left {
                left_null_dyn(dense, &input).unwrap()
            } else {
                right_null_dyn(dense, &input).unwrap()
            }
        };
        let before = stages();
        let first = null(&mut dense);
        assert_eq!(stages() - before, 1);
        let second = null(&mut dense);
        assert_eq!(stages() - before, 2);
        assert!(Arc::ptr_eq(
            first.space().space().structure(),
            second.space().space().structure()
        ));
    }
}
