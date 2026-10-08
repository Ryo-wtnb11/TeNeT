use super::*;

#[cfg(feature = "racah-generated")]
#[test]
fn sun_endomorphism_row_and_column_tree_stacking_is_identical() {
    use std::collections::BTreeMap;

    use tenet::sector::SUNFusionRule;
    use tenet::typed::MultiplicityIndex;

    type TreePlacement = (
        Vec<Vec<i64>>,
        Vec<Vec<i64>>,
        Vec<MultiplicityIndex>,
        usize,
        Vec<usize>,
    );

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    for (n, label) in [(3, vec![1, 1]), (4, vec![1, 0, 1])] {
        let provider = Arc::new(SUNFusionRule::new(n).unwrap());
        let leg = GradedSpace::try_new(Arc::clone(&provider), [(label, 2)]).unwrap();
        let source: TensorMap<_, f64> =
            TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&leg, &leg], |_, _| 0.0).unwrap();
        let mut stacks = BTreeMap::<Vec<i64>, (Vec<TreePlacement>, Vec<TreePlacement>)>::new();
        for index in 0..source.subblock_count() {
            let block = source.subblock(index).unwrap();
            let trees = source.subblock_fusion_trees(index).unwrap();
            let entry = stacks.entry(trees.coupled().clone()).or_default();
            let row_key = (
                trees.codomain_uncoupled().to_vec(),
                trees.codomain_innerlines().to_vec(),
                trees.codomain_vertices().to_vec(),
            );
            if !entry.0.iter().any(|placed| {
                placed.0 == row_key.0 && placed.1 == row_key.1 && placed.2 == row_key.2
            }) {
                let offset = entry
                    .0
                    .iter()
                    .map(|placed| placed.4.iter().product::<usize>())
                    .sum();
                entry.0.push((
                    row_key.0,
                    row_key.1,
                    row_key.2,
                    offset,
                    block.shape()[..2].to_vec(),
                ));
            }
            let col_key = (
                trees.domain_uncoupled().to_vec(),
                trees.domain_innerlines().to_vec(),
                trees.domain_vertices().to_vec(),
            );
            if !entry.1.iter().any(|placed| {
                placed.0 == col_key.0 && placed.1 == col_key.1 && placed.2 == col_key.2
            }) {
                let offset = entry
                    .1
                    .iter()
                    .map(|placed| placed.4.iter().product::<usize>())
                    .sum();
                entry.1.push((
                    col_key.0,
                    col_key.1,
                    col_key.2,
                    offset,
                    block.shape()[2..].to_vec(),
                ));
            }
        }
        assert!(stacks.values().any(|(rows, _)| {
            rows.iter()
                .any(|row| row.2.iter().any(|vertex| vertex.get() > 1))
        }));
        for (sector, (rows, columns)) in stacks {
            assert_eq!(rows, columns, "SU({n}) stacking mismatch in {sector:?}");
        }
    }
}

/// #1449: like TensorKit `adjoint(::DiagonalTensorMap)` and the
/// multiplicity-free path, the checked-Generic adjoint of a compact diagonal is
/// the owned conjugated diagonal, and its unstored zeros stay `+0 + 0i`.
#[cfg(feature = "racah-generated")]
#[test]
fn checked_generic_complex_diagonal_adjoint_is_the_owned_conjugated_diagonal() {
    use tenet::sector::SUNFusionRule;
    use tenet::sector::{U1FusionRule, U1Irrep};

    fn bits<R: TypedSectorAdmission>(tensor: &TensorMap<R, Complex64>) -> Vec<(u64, u64)> {
        tensor
            .materialize()
            .unwrap()
            .dense_data()
            .unwrap()
            .iter()
            .map(|z| (z.re.to_bits(), z.im.to_bits()))
            .collect()
    }
    // Each structural zero must be `+0 + 0i`; an `im` of `-0` fails.
    fn assert_positive_zeros<R: TypedSectorAdmission>(
        tensor: &TensorMap<R, Complex64>,
        count: usize,
    ) {
        let zeros: Vec<_> = bits(tensor)
            .into_iter()
            .filter(|&(re, im)| f64::from_bits(re) == 0.0 && f64::from_bits(im) == 0.0)
            .collect();
        assert_eq!(zeros, vec![(0, 0); count]);
    }
    let conj_if = |conj: bool, values: &[(f64, f64)]| -> Vec<Complex64> {
        values
            .iter()
            .map(|&(re, im)| Complex64::new(re, if conj { -im } else { im }))
            .collect()
    };

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(SUNFusionRule::new(3).unwrap());
    let leg = GradedSpace::try_new(provider, [(vec![2i64, 1], 3), (vec![0, 0], 2)]).unwrap();
    let big = [(1.5, 0.5), (-2.0, -1.0), (0.25, 3.0)];
    let small = [(3.0, -0.75), (-0.5, 2.0)];
    let su3 = |conj: bool| {
        TensorMap::<_, Complex64>::diagonal(
            &runtime,
            &leg,
            [
                SectorSpectrum {
                    sector: vec![2i64, 1],
                    values: conj_if(conj, &big),
                },
                SectorSpectrum {
                    sector: vec![0, 0],
                    values: conj_if(conj, &small),
                },
            ],
        )
        .unwrap()
    };
    let s = su3(false);
    let adjoint = s.adjoint().unwrap();
    // Hand-conjugated values are the oracle.
    let expected = su3(true);
    // 3x3 [2,1] and 2x2 [0,0] blocks: 6 + 2 off-diagonal entries.
    assert_positive_zeros(&adjoint, 8);
    assert_eq!(bits(&adjoint), bits(&expected));
    assert!(
        tenet::typed::__network::network_reuse_class(&adjoint, false) == NetworkReuseClass::Compact
    );
    assert_eq!(
        tenet::expert::diagonal_spectrum(&adjoint).unwrap(),
        tenet::expert::diagonal_spectrum(&expected).unwrap()
    );
    assert_eq!(
        tenet::expert::diagonal_spectrum(&adjoint.adjoint().unwrap()).unwrap(),
        tenet::expert::diagonal_spectrum(&s).unwrap()
    );

    let assert_close = |got: &[Complex64], want: &[Complex64], what: &str| {
        assert_eq!(got.len(), want.len(), "{what}");
        for (got, want) in got.iter().zip(want) {
            assert!((got - want).norm() <= 1e-12, "{what}");
        }
    };
    // Consumers take the owned compact form as they take `s` itself.
    let Qr { q, r } = adjoint.qr_compact(&[0], &[1]).unwrap();
    assert_close(
        q.compose(&r).unwrap().dense_data().unwrap(),
        adjoint.materialize().unwrap().dense_data().unwrap(),
        "qr",
    );
    let Svd { u, s: sigma, vh } = adjoint.svd_compact(&[0], &[1]).unwrap();
    let reconstructed = u.compose(&sigma).unwrap().compose(&vh).unwrap();
    assert_close(
        reconstructed.dense_data().unwrap(),
        adjoint.materialize().unwrap().dense_data().unwrap(),
        "svd",
    );
    // s^† s is diagonal with |s|^2 entries.
    let gram = adjoint.compose(&s).unwrap();
    let norms = |values: &[(f64, f64)]| -> Vec<Complex64> {
        values
            .iter()
            .map(|&(re, im)| Complex64::new(re * re + im * im, 0.0))
            .collect()
    };
    let expected_gram = TensorMap::<_, Complex64>::diagonal(
        &runtime,
        &leg,
        [
            SectorSpectrum {
                sector: vec![2i64, 1],
                values: norms(&big),
            },
            SectorSpectrum {
                sector: vec![0, 0],
                values: norms(&small),
            },
        ],
    )
    .unwrap();
    assert_close(
        gram.dense_data().unwrap(),
        expected_gram.materialize().unwrap().dense_data().unwrap(),
        "s^† s",
    );

    // Non-self-dual SU(3) irreps on a dual leg (`[1,0]^2 + [0,1]` dualized to
    // `[0,1]^2 + [1,0]`): the adjoint keeps the space, not its dual, and
    // conjugates the values.
    let provider = Arc::new(SUNFusionRule::new(3).unwrap());
    let chiral = GradedSpace::try_new(provider, [(vec![1i64, 0], 2), (vec![0, 1], 1)])
        .unwrap()
        .try_dual()
        .unwrap();
    let triplets = [(0.5, -1.25), (2.0, 0.75)];
    let antitriplet = [(-1.0, 4.0)];
    let chiral_diagonal = |conj: bool| {
        TensorMap::<_, Complex64>::diagonal(
            &runtime,
            &chiral,
            [
                SectorSpectrum {
                    sector: vec![0i64, 1],
                    values: conj_if(conj, &triplets),
                },
                SectorSpectrum {
                    sector: vec![1, 0],
                    values: conj_if(conj, &antitriplet),
                },
            ],
        )
        .unwrap()
    };
    let source = chiral_diagonal(false);
    let chiral_adjoint = source.adjoint().unwrap();
    assert_eq!(chiral_adjoint.codomain(), source.codomain());
    assert_eq!(chiral_adjoint.domain(), source.domain());
    assert_eq!(chiral_adjoint.codomain()[0], chiral);
    assert_eq!(
        tenet::expert::diagonal_spectrum(&chiral_adjoint).unwrap(),
        tenet::expert::diagonal_spectrum(&chiral_diagonal(true)).unwrap()
    );
    assert_eq!(bits(&chiral_adjoint), bits(&chiral_diagonal(true)));
    // 2x2 [0,1] block and 1x1 [1,0] block: 2 off-diagonal entries.
    assert_positive_zeros(&chiral_adjoint, 2);

    // A real diagonal is its own adjoint (TensorKit returns `d`).
    let real = TensorMap::<_, f64>::diagonal(
        &runtime,
        &chiral,
        [
            SectorSpectrum {
                sector: vec![0i64, 1],
                values: vec![0.5, 2.0],
            },
            SectorSpectrum {
                sector: vec![1, 0],
                values: vec![-1.0],
            },
        ],
    )
    .unwrap();
    let real_adjoint = real.adjoint().unwrap();
    assert!(
        tenet::typed::__network::network_reuse_class(&real_adjoint, false)
            == NetworkReuseClass::Compact
    );
    assert_eq!(real_adjoint.codomain(), real.codomain());
    assert_eq!(
        tenet::expert::diagonal_spectrum(&real_adjoint).unwrap(),
        tenet::expert::diagonal_spectrum(&real).unwrap()
    );

    // The multiplicity-free path gives the same representation and zeros.
    let u1 = GradedSpace::try_new(
        Arc::new(U1FusionRule),
        [(U1Irrep::new(1), 3), (U1Irrep::new(0), 2)],
    )
    .unwrap();
    let u1_diagonal = |conj: bool| {
        TensorMap::<_, Complex64>::diagonal(
            &runtime,
            &u1,
            [
                SectorSpectrum {
                    sector: U1Irrep::new(1),
                    values: conj_if(conj, &big),
                },
                SectorSpectrum {
                    sector: U1Irrep::new(0),
                    values: conj_if(conj, &small),
                },
            ],
        )
        .unwrap()
    };
    let mf_adjoint = u1_diagonal(false).adjoint().unwrap();
    assert!(
        tenet::typed::__network::network_reuse_class(&mf_adjoint, false)
            == NetworkReuseClass::Compact
    );
    assert_eq!(bits(&mf_adjoint), bits(&u1_diagonal(true)));
    assert_positive_zeros(&mf_adjoint, 8);
}

#[test]
fn checked_only_multiplicity_two_transforms_keep_the_source_authority() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(0));
    let leg = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&leg, &leg, &leg], [], |trees, _| {
            trees.codomain_vertices()[0].get() as f64
        })
        .unwrap();
    let snapshot = |tensor: &TensorMap<CheckedOnlyToy, f64>| {
        (0..tensor.subblock_count())
            .map(|index| tensor.subblock_fusion_trees(index).unwrap())
            .collect::<Vec<_>>()
    };
    let source_snapshot = snapshot(&source);
    provider.coefficient_queries.store(0, Ordering::Relaxed);
    let error = source.braid(&[1, 0, 2], &[], &[0, 1]).unwrap_err();
    assert!(matches!(error, GenericTensorError::Facade(_)));
    assert_eq!(provider.coefficient_queries.load(Ordering::Relaxed), 0);

    let permuted = source.permute(&[1, 0, 2], &[]).unwrap();
    assert!(std::ptr::eq(permuted.provider(), provider.as_ref()));
    let restored = permuted.permute(&[1, 0, 2], &[]).unwrap();
    assert_eq!(snapshot(&restored), source_snapshot);
    for (actual, expected) in restored
        .dense_data()
        .unwrap()
        .iter()
        .zip(source.dense_data().unwrap())
    {
        assert!((actual - expected).abs() <= 1e-12);
    }

    let braided = source.braid(&[1, 0, 2], &[], &[0, 1, 2]).unwrap();
    assert!(std::ptr::eq(braided.provider(), provider.as_ref()));

    provider.fail_algebra.store(true, Ordering::Relaxed);
    let error = source.permute(&[1, 0, 2], &[]).unwrap_err();
    assert!(matches!(
        error,
        GenericTensorError::Plan(tenet::typed::CheckedGenericPlanError::Provider(
            ToyError::Algebra
        ))
    ));
}

#[cfg(feature = "racah-generated")]
#[test]
fn sun_checked_generic_unit_insert_remove_preserves_authority_and_payload() {
    use tenet::sector::SUNFusionRule;

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    for n in [3, 4] {
        let provider = Arc::new(SUNFusionRule::new(n).unwrap());
        let label = if n == 3 { vec![1, 1] } else { vec![1, 0, 1] };
        let leg = GradedSpace::try_new(Arc::clone(&provider), [(label, 1)]).unwrap();
        let source: TensorMap<_, f64> =
            TensorMap::from_subblock_fn(&runtime, [&leg], [&leg], |_, _| 2.0).unwrap();

        assert!(source.remove_unit(0).is_err());
        let inserted = source
            .insert_unit(0, Side::Domain, tenet::typed::Duality::Plain)
            .unwrap();
        assert!(std::ptr::eq(inserted.provider(), provider.as_ref()));
        assert_eq!(
            inserted.dense_data().unwrap().as_ptr(),
            source.dense_data().unwrap().as_ptr()
        );
        let removed = inserted.remove_unit(0).unwrap();
        assert!(std::ptr::eq(removed.provider(), provider.as_ref()));
        assert_eq!(
            removed.dense_data().unwrap().as_ptr(),
            source.dense_data().unwrap().as_ptr()
        );
        assert_eq!(removed.dense_data().unwrap(), source.dense_data().unwrap());

        // The seam decides only the boundary slot `position == codomain_rank`.
        for (seam, codomain_rank) in [(Side::Codomain, 2), (Side::Domain, 1)] {
            let inserted = source
                .insert_unit(1, seam, tenet::typed::Duality::Dual)
                .unwrap();
            assert_eq!(inserted.codomain_rank(), codomain_rank, "{seam:?}");
            let unit = match seam {
                Side::Codomain => inserted.codomain()[1].clone(),
                Side::Domain => inserted.domain()[0].clone(),
            };
            assert!(unit.is_dual(), "{seam:?}");
            assert!(std::ptr::eq(inserted.provider(), provider.as_ref()));
            assert_eq!(
                inserted.dense_data().unwrap().as_ptr(),
                source.dense_data().unwrap().as_ptr()
            );
        }
    }
}

#[test]
fn checked_unit_insert_correspondence_failure_does_not_publish_destination() {
    if run_isolated_or_return(
        "TENET_CHECKED_UNIT_INSERT_CORRESPONDENCE_FAILURE_ISOLATED",
        "transforms::checked_unit_insert_correspondence_failure_does_not_publish_destination",
    ) {
        return;
    }
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(241));
    let x = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&x], [&x, &x], |_, _| 3.0).unwrap();

    // Negative fixture only: after the source exists, claim a second channel
    // for 1 x X. Destination preparation succeeds, but the larger layout no
    // longer corresponds to inserting an identity leg into `source`.
    provider.unit_layout_fault.store(1, Ordering::Relaxed);
    forget_cached_structures();
    let before =
        tenet::expert::structure_cache_info(tenet::expert::StructureCacheKind::DegeneracyStructure);
    assert_eq!(before.entries(), 0);

    let error = source
        .insert_unit(0, Side::Codomain, tenet::typed::Duality::Plain)
        .unwrap_err();

    assert!(matches!(
        error,
        GenericTensorError::Structure(CheckedGenericStructureError::Core(
            tenet::typed::CoreError::UnitLayoutCorrespondence
        ))
    ));
    let after =
        tenet::expert::structure_cache_info(tenet::expert::StructureCacheKind::DegeneracyStructure);
    assert_eq!(after.admissions(), before.admissions());
    assert_eq!(after.entries(), before.entries());
    assert_eq!(after.charged_bytes(), before.charged_bytes());
}

#[test]
fn checked_unit_remove_correspondence_failure_does_not_publish_destination() {
    if run_isolated_or_return(
        "TENET_CHECKED_UNIT_REMOVE_CORRESPONDENCE_FAILURE_ISOLATED",
        "transforms::checked_unit_remove_correspondence_failure_does_not_publish_destination",
    ) {
        return;
    }
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(242));
    let x = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let vacuum = GradedSpace::try_new(Arc::clone(&provider), [(Label::Vacuum, 1)]).unwrap();
    let base: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&x, &x], [&vacuum], |_, _| 5.0).unwrap();
    let source = base
        .insert_unit(0, Side::Codomain, tenet::typed::Duality::Plain)
        .unwrap();

    // Negative fixture only: rebuild the destination after suppressing the
    // X x X -> 1 channel that the already-built source still contains.
    provider.unit_layout_fault.store(2, Ordering::Relaxed);
    forget_cached_structures();
    let before =
        tenet::expert::structure_cache_info(tenet::expert::StructureCacheKind::DegeneracyStructure);
    assert_eq!(before.entries(), 0);

    let error = source.remove_unit(0).unwrap_err();

    assert!(matches!(
        error,
        GenericTensorError::Structure(CheckedGenericStructureError::Core(
            tenet::typed::CoreError::UnitLayoutCorrespondence
        ))
    ));
    let after =
        tenet::expert::structure_cache_info(tenet::expert::StructureCacheKind::DegeneracyStructure);
    assert_eq!(after.admissions(), before.admissions());
    assert_eq!(after.entries(), before.entries());
    assert_eq!(after.charged_bytes(), before.charged_bytes());
}

#[test]
fn checked_unit_final_provider_guard_remains_structure_typed() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(243));
    let x = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&x], [&x], |_, _| 7.0).unwrap();
    let payload = source.dense_data().unwrap().as_ptr();

    reset_provider_queries(&provider);
    provider
        .invalid_style_after_first_query
        .store(true, Ordering::Relaxed);
    let error = source
        .insert_unit(0, Side::Codomain, tenet::typed::Duality::Plain)
        .unwrap_err();

    assert!(matches!(
        error,
        GenericTensorError::Structure(CheckedGenericStructureError::Core(
            tenet::typed::CoreError::UnsupportedFusionStyle {
                expected: FusionStyleKind::Generic,
                actual: FusionStyleKind::Unique,
            }
        ))
    ));
    assert_eq!(provider.style_queries.load(Ordering::Relaxed), 2);
    assert_eq!(source.dense_data().unwrap().as_ptr(), payload);
    assert_eq!(source.dense_data().unwrap(), &[7.0]);
}

#[test]
fn checked_only_contract_and_compose_keep_left_authority() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let left_provider = Arc::new(CheckedOnlyToy::new(124));
    let right_provider = Arc::new(CheckedOnlyToy::new(124));
    let left_leg = GradedSpace::try_new(Arc::clone(&left_provider), [(Label::X, 1)]).unwrap();
    let right_leg = GradedSpace::try_new(Arc::clone(&right_provider), [(Label::X, 1)]).unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&left_leg], [&left_leg], |_, _| 1.0).unwrap();
    let nontrivial: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&left_leg, &left_leg], [&left_leg], |_, _| 1.0)
            .unwrap();
    let identity: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&right_leg], [&right_leg], |_, _| 1.0).unwrap();
    left_provider.r_queries.store(0, Ordering::Relaxed);

    for output in [
        source
            .contract(
                &identity,
                &ContractSpec {
                    lhs: &[1],
                    rhs: &[0],
                    codomain: &[0],
                    domain: &[1],
                },
            )
            .unwrap(),
        source.compose(&identity).unwrap(),
    ] {
        assert!(std::ptr::eq(output.provider(), left_provider.as_ref()));
        assert_eq!(output.dense_data().unwrap(), source.dense_data().unwrap());
        for index in 0..source.subblock_count() {
            assert_eq!(
                output.subblock_fusion_trees(index).unwrap(),
                source.subblock_fusion_trees(index).unwrap()
            );
        }
    }
    assert_eq!(left_provider.r_queries.load(Ordering::Relaxed), 0);

    let other_runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let foreign_runtime_identity: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&other_runtime, [&right_leg], [&right_leg], |_, _| 1.0)
            .unwrap();
    left_provider.algebra_queries.store(0, Ordering::Relaxed);
    right_provider.algebra_queries.store(0, Ordering::Relaxed);
    assert!(matches!(
        source.contract(
            &foreign_runtime_identity,
            &ContractSpec {
                lhs: &[1],
                rhs: &[0],
                codomain: &[0],
                domain: &[1]
            }
        ),
        Err(GenericTensorError::Facade(
            tenet::typed::Error::RuntimeMismatch
        ))
    ));
    assert_eq!(left_provider.algebra_queries.load(Ordering::Relaxed), 0);
    assert_eq!(right_provider.algebra_queries.load(Ordering::Relaxed), 0);

    let wrong_provider = Arc::new(CheckedOnlyToy::new(1));
    let wrong_leg = GradedSpace::try_new(Arc::clone(&wrong_provider), [(Label::X, 1)]).unwrap();
    let wrong_identity: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&wrong_leg], [&wrong_leg], |_, _| 1.0).unwrap();
    left_provider.algebra_queries.store(0, Ordering::Relaxed);
    wrong_provider.algebra_queries.store(0, Ordering::Relaxed);
    assert!(source
        .contract(
            &wrong_identity,
            &ContractSpec {
                lhs: &[1],
                rhs: &[0],
                codomain: &[0],
                domain: &[1]
            }
        )
        .is_err());
    assert_eq!(left_provider.algebra_queries.load(Ordering::Relaxed), 0);
    assert_eq!(wrong_provider.algebra_queries.load(Ordering::Relaxed), 0);

    // See `forget_cached_structures`: this tag is this test's alone.
    forget_cached_structures();
    left_provider.fail_algebra.store(true, Ordering::Relaxed);
    let error = nontrivial
        .contract(
            &identity,
            &ContractSpec {
                lhs: &[2],
                rhs: &[0],
                codomain: &[0, 1],
                domain: &[2],
            },
        )
        .unwrap_err();
    assert!(matches!(
        error,
        GenericTensorError::Plan(tenet::typed::CheckedGenericPlanError::Provider(
            ToyError::Algebra
        ))
    ));
}

#[test]
fn checked_only_identity_transforms_make_no_provider_queries() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(0));
    let leg = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&leg], |_, indices| {
            indices.iter().sum::<usize>() as f64 + 1.0
        })
        .unwrap();

    for counter in [
        &provider.identity_queries,
        &provider.style_queries,
        &provider.algebra_queries,
        &provider.coefficient_queries,
        &provider.f_queries,
        &provider.r_queries,
        &provider.postcommit_queries,
    ] {
        counter.store(0, Ordering::Relaxed);
    }

    for output in [
        source.permute(&[0, 1], &[2]).unwrap(),
        source.braid(&[0, 1], &[2], &[2, 1, 0]).unwrap(),
        source.transpose(&[0, 1], &[2]).unwrap(),
        source.repartition(2).unwrap(),
    ] {
        assert!(std::ptr::eq(output.provider(), provider.as_ref()));
        assert_eq!(
            output.dense_data().unwrap().as_ptr(),
            source.dense_data().unwrap().as_ptr()
        );
    }
    for counter in [
        &provider.identity_queries,
        &provider.style_queries,
        &provider.algebra_queries,
        &provider.coefficient_queries,
        &provider.f_queries,
        &provider.r_queries,
        &provider.postcommit_queries,
    ] {
        assert_eq!(counter.load(Ordering::Relaxed), 0);
    }
}

#[test]
fn checked_only_otimes_preserves_typed_late_f_failures() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new_product_probe(0));
    let leg = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&leg, &leg], |trees, _| {
            trees.codomain_vertices()[0].get() as f64
                - 2.0 * trees.domain_vertices()[0].get() as f64
        })
        .unwrap();

    provider.f_queries.store(0, Ordering::Relaxed);
    source.otimes(&source).unwrap();
    let final_f_query = provider.f_queries.load(Ordering::Relaxed);
    assert!(final_f_query > 1);
    provider.f_queries.store(0, Ordering::Relaxed);
    provider.reset_commit_spy();
    provider
        .fail_f_on_query
        .store(final_f_query, Ordering::Relaxed);
    let error = source.otimes(&source).unwrap_err();
    assert!(matches!(
        error,
        GenericTensorError::TensorProduct(CheckedGenericTensorProductError::Provider(
            ToyError::Algebra
        ))
    ));
    assert_eq!(provider.f_queries.load(Ordering::Relaxed), final_f_query);
    assert_eq!(provider.commit_count.load(Ordering::Relaxed), 0);
    provider.fail_f_on_query.store(0, Ordering::Relaxed);

    provider.f_queries.store(0, Ordering::Relaxed);
    provider.reset_commit_spy();
    provider.malformed_f.store(true, Ordering::Relaxed);
    let error = source.otimes(&source).unwrap_err();
    assert!(matches!(
        error,
        GenericTensorError::TensorProduct(CheckedGenericTensorProductError::SymbolShape {
            symbol: "F",
            ..
        })
    ));
    assert_eq!(provider.commit_count.load(Ordering::Relaxed), 0);
    assert_eq!(provider.r_queries.load(Ordering::Relaxed), 0);
}

#[test]
fn checked_only_otimes_rejects_runtime_identity_and_style_before_algebra() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let other_runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let first = Arc::new(CheckedOnlyToy::new(0));
    let mismatched = Arc::new(CheckedOnlyToy::new(1));
    let first_leg = GradedSpace::try_new(Arc::clone(&first), [(Label::X, 1)]).unwrap();
    let mismatched_leg = GradedSpace::try_new(Arc::clone(&mismatched), [(Label::X, 1)]).unwrap();
    let lhs: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&first_leg, &first_leg], [&first_leg], |_, _| 1.0)
            .unwrap();
    let wrong_runtime: TensorMap<_, f64> = TensorMap::from_subblock_fn(
        &other_runtime,
        [&first_leg, &first_leg],
        [&first_leg],
        |_, _| 1.0,
    )
    .unwrap();
    let wrong_identity: TensorMap<_, f64> = TensorMap::from_subblock_fn(
        &runtime,
        [&mismatched_leg, &mismatched_leg],
        [&mismatched_leg],
        |_, _| 1.0,
    )
    .unwrap();
    first.algebra_queries.store(0, Ordering::Relaxed);
    first.coefficient_queries.store(0, Ordering::Relaxed);
    mismatched.algebra_queries.store(0, Ordering::Relaxed);
    mismatched.coefficient_queries.store(0, Ordering::Relaxed);

    assert!(matches!(
        lhs.otimes(&wrong_runtime),
        Err(GenericTensorError::Facade(_))
    ));
    assert!(matches!(
        lhs.otimes(&wrong_identity),
        Err(GenericTensorError::TensorProduct(
            CheckedGenericTensorProductError::Core(_)
        ))
    ));
    first.invalid_style.store(true, Ordering::Relaxed);
    assert!(matches!(
        lhs.otimes(&lhs),
        Err(GenericTensorError::TensorProduct(
            CheckedGenericTensorProductError::Core(_)
        ))
    ));
    assert_eq!(first.algebra_queries.load(Ordering::Relaxed), 0);
    assert_eq!(first.coefficient_queries.load(Ordering::Relaxed), 0);
    assert_eq!(mismatched.algebra_queries.load(Ordering::Relaxed), 0);
    assert_eq!(mismatched.coefficient_queries.load(Ordering::Relaxed), 0);
}

#[test]
fn checked_only_otimes_matches_fixed_heterogeneous_nonunit_oracle() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let first = Arc::new(CheckedOnlyToy::new_product_probe(9));
    let second = Arc::new(CheckedOnlyToy::new_product_probe(9));
    let x2 = GradedSpace::try_new(Arc::clone(&first), [(Label::X, 2)]).unwrap();
    let x1 = GradedSpace::try_new(Arc::clone(&first), [(Label::X, 1)]).unwrap();
    let y3 = GradedSpace::try_new(Arc::clone(&second), [(Label::One, 3)]).unwrap();
    let y1 = GradedSpace::try_new(Arc::clone(&second), [(Label::One, 1)]).unwrap();
    let rhs_x1 = GradedSpace::try_new(Arc::clone(&second), [(Label::X, 1)]).unwrap();
    let lhs: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&x2, &x1], [&x1, &x1], |trees, index| {
            100.0 * trees.codomain_vertices()[0].get() as f64
                + 10.0 * trees.domain_vertices()[0].get() as f64
                + index[0] as f64
                + 1.0
        })
        .unwrap();
    let rhs: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&y3, &rhs_x1], [&y1, &rhs_x1], |_, index| {
            index[0] as f64 + 1.0
        })
        .unwrap();
    for provider in [&first, &second] {
        provider.identity_queries.store(0, Ordering::Relaxed);
        provider.style_queries.store(0, Ordering::Relaxed);
        provider.algebra_queries.store(0, Ordering::Relaxed);
        provider.coefficient_queries.store(0, Ordering::Relaxed);
        provider.r_queries.store(0, Ordering::Relaxed);
        provider.f_queries.store(0, Ordering::Relaxed);
        provider.reset_commit_spy();
    }
    let output = lhs.otimes(&rhs).unwrap();
    assert!(std::ptr::eq(output.provider(), first.as_ref()));
    // One identity query more than the walks themselves: the
    // sector-structure cache key (#2030).
    assert_eq!(first.identity_queries.load(Ordering::Relaxed), 4);
    assert_eq!(second.identity_queries.load(Ordering::Relaxed), 1);
    assert_eq!(first.commit_count.load(Ordering::Relaxed), 1);
    assert_eq!(second.commit_count.load(Ordering::Relaxed), 0);
    assert_eq!(first.postcommit_queries.load(Ordering::Relaxed), 0);
    assert_eq!(second.postcommit_queries.load(Ordering::Relaxed), 0);
    assert!(first.algebra_queries.load(Ordering::Relaxed) > 0);
    assert!(first.f_queries.load(Ordering::Relaxed) > 0);
    assert_eq!(first.r_queries.load(Ordering::Relaxed), 0);
    assert_eq!(second.algebra_queries.load(Ordering::Relaxed), 0);
    assert_eq!(second.coefficient_queries.load(Ordering::Relaxed), 0);
    assert_eq!(second.f_queries.load(Ordering::Relaxed), 0);
    assert_eq!(second.r_queries.load(Ordering::Relaxed), 0);

    const EXPECTED_KEYS: [([usize; 3], [usize; 3]); 16] = [
        ([1, 1, 1], [1, 1, 1]),
        ([2, 1, 1], [1, 1, 1]),
        ([1, 1, 2], [1, 1, 1]),
        ([2, 1, 2], [1, 1, 1]),
        ([1, 1, 1], [2, 1, 1]),
        ([2, 1, 1], [2, 1, 1]),
        ([1, 1, 2], [2, 1, 1]),
        ([2, 1, 2], [2, 1, 1]),
        ([1, 1, 1], [1, 1, 2]),
        ([2, 1, 1], [1, 1, 2]),
        ([1, 1, 2], [1, 1, 2]),
        ([2, 1, 2], [1, 1, 2]),
        ([1, 1, 1], [2, 1, 2]),
        ([2, 1, 1], [2, 1, 2]),
        ([1, 1, 2], [2, 1, 2]),
        ([2, 1, 2], [2, 1, 2]),
    ];
    let keys = (0..output.subblock_count())
        .map(|index| {
            let trees = output.subblock_fusion_trees(index).unwrap();
            assert_eq!(
                trees.codomain_uncoupled(),
                &[Label::X, Label::X, Label::One, Label::X]
            );
            assert_eq!(
                trees.domain_uncoupled(),
                &[Label::X, Label::X, Label::One, Label::X]
            );
            assert_eq!(
                output.subblock(index).unwrap().shape(),
                &[2, 1, 3, 1, 1, 1, 1, 1]
            );
            (
                trees
                    .codomain_vertices()
                    .iter()
                    .map(|vertex| vertex.get())
                    .collect::<Vec<_>>()
                    .try_into()
                    .unwrap(),
                trees
                    .domain_vertices()
                    .iter()
                    .map(|vertex| vertex.get())
                    .collect::<Vec<_>>()
                    .try_into()
                    .unwrap(),
            )
        })
        .collect::<Vec<_>>();
    assert_eq!(keys, EXPECTED_KEYS);

    const EXPECTED_DATA: [f64; 96] = [
        555.0, 560.0, 1110.0, 1120.0, 1665.0, 1680.0, 1055.0, 1060.0, 2110.0, 2120.0, 3165.0,
        3180.0, 1221.0, 1232.0, 2442.0, 2464.0, 3663.0, 3696.0, 2321.0, 2332.0, 4642.0, 4664.0,
        6963.0, 6996.0, 605.0, 610.0, 1210.0, 1220.0, 1815.0, 1830.0, 1105.0, 1110.0, 2210.0,
        2220.0, 3315.0, 3330.0, 1331.0, 1342.0, 2662.0, 2684.0, 3993.0, 4026.0, 2431.0, 2442.0,
        4862.0, 4884.0, 7293.0, 7326.0, 1221.0, 1232.0, 2442.0, 2464.0, 3663.0, 3696.0, 2321.0,
        2332.0, 4642.0, 4664.0, 6963.0, 6996.0, 2775.0, 2800.0, 5550.0, 5600.0, 8325.0, 8400.0,
        5275.0, 5300.0, 10550.0, 10600.0, 15825.0, 15900.0, 1331.0, 1342.0, 2662.0, 2684.0, 3993.0,
        4026.0, 2431.0, 2442.0, 4862.0, 4884.0, 7293.0, 7326.0, 3025.0, 3050.0, 6050.0, 6100.0,
        9075.0, 9150.0, 5525.0, 5550.0, 11050.0, 11100.0, 16575.0, 16650.0,
    ];
    assert_eq!(output.dense_data().unwrap(), EXPECTED_DATA);

    // The first stored value has two nonzero root-multiplicity paths:
    // μ=1 contributes 111*1 and μ=2 contributes 111*4. The fixed result
    // therefore kills overwrite-instead-of-accumulate mutations.
    let colliding_path_coefficients = [1.0, 4.0];
    assert_eq!(colliding_path_coefficients.len(), 2);
    assert_eq!(
        111.0 * colliding_path_coefficients.iter().sum::<f64>(),
        EXPECTED_DATA[0]
    );

    let complex_lhs: TensorMap<_, Complex64> =
        TensorMap::from_subblock_fn(&runtime, [&x2, &x1], [&x1, &x1], |trees, index| {
            Complex64::new(1.0, 1.0)
                * (100.0 * trees.codomain_vertices()[0].get() as f64
                    + 10.0 * trees.domain_vertices()[0].get() as f64
                    + index[0] as f64
                    + 1.0)
        })
        .unwrap();
    let complex_rhs: TensorMap<_, Complex64> =
        TensorMap::from_subblock_fn(&runtime, [&y3, &rhs_x1], [&y1, &rhs_x1], |_, index| {
            Complex64::new(2.0, -3.0) * (index[0] as f64 + 1.0)
        })
        .unwrap();
    first.f_queries.store(0, Ordering::Relaxed);
    first.reset_commit_spy();
    let complex = complex_lhs.otimes(&complex_rhs).unwrap();
    assert!(std::ptr::eq(complex.provider(), first.as_ref()));
    for (actual, expected) in complex.dense_data().unwrap().iter().zip(EXPECTED_DATA) {
        assert!((*actual - Complex64::new(5.0, -1.0) * expected).norm() <= 1e-12);
    }
}

#[test]
fn checked_generic_cat_admits_once_and_queries_only_left_before_commit() {
    // What: successful catdomain admission uses the left provider Arc once;
    // admitted identity stamps keep the equal-identity right provider cold,
    // and copy planning performs no provider query after commit.
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let left_provider = Arc::new(CheckedOnlyToy::new(0));
    let right_provider = Arc::new(CheckedOnlyToy::new(0));
    let left_common = GradedSpace::try_new(Arc::clone(&left_provider), [(Label::X, 1)]).unwrap();
    let right_common = GradedSpace::try_new(Arc::clone(&right_provider), [(Label::X, 1)]).unwrap();
    let left_changed = GradedSpace::try_new(Arc::clone(&left_provider), [(Label::X, 1)]).unwrap();
    let right_changed = GradedSpace::try_new(Arc::clone(&right_provider), [(Label::X, 2)]).unwrap();
    let lhs: TensorMap<_, f64> = TensorMap::from_subblock_fn(
        &runtime,
        [&left_common, &left_common],
        [&left_changed],
        |trees, indices| {
            10.0 + trees.codomain_vertices()[0].get() as f64 + indices.iter().sum::<usize>() as f64
        },
    )
    .unwrap();
    let rhs: TensorMap<_, f64> = TensorMap::from_subblock_fn(
        &runtime,
        [&right_common, &right_common],
        [&right_changed],
        |trees, indices| {
            20.0 + trees.codomain_vertices()[0].get() as f64 + indices.iter().sum::<usize>() as f64
        },
    )
    .unwrap();
    let combined = left_changed.oplus(&right_changed).unwrap();
    for provider in [&left_provider, &right_provider] {
        for counter in [
            &provider.identity_queries,
            &provider.style_queries,
            &provider.algebra_queries,
            &provider.coefficient_queries,
            &provider.f_queries,
            &provider.r_queries,
        ] {
            counter.store(0, Ordering::Relaxed);
        }
        provider.reset_commit_spy();
    }
    let _: TensorMap<_, f64> =
        TensorMap::zeros(&runtime, [&left_common, &left_common], [&combined]).unwrap();
    let mut admission_queries = [
        left_provider.identity_queries.load(Ordering::Relaxed),
        left_provider.style_queries.load(Ordering::Relaxed),
        left_provider.algebra_queries.load(Ordering::Relaxed),
        left_provider.coefficient_queries.load(Ordering::Relaxed),
        left_provider.f_queries.load(Ordering::Relaxed),
        left_provider.r_queries.load(Ordering::Relaxed),
    ];
    let admission_query_count = left_provider.queries_since_reset.load(Ordering::Relaxed) - 3;
    // `zeros` first checks the three supplied leg authorities; cat starts from
    // already-admitted stamps, so remove exactly those three identity reads.
    admission_queries[0] -= 3;
    for counter in [
        &left_provider.identity_queries,
        &left_provider.style_queries,
        &left_provider.algebra_queries,
        &left_provider.coefficient_queries,
        &left_provider.f_queries,
        &left_provider.r_queries,
    ] {
        counter.store(0, Ordering::Relaxed);
    }
    left_provider.arm_commit_spy_after_queries(admission_query_count);

    let output = lhs.cat(&rhs, Side::Domain).unwrap();

    assert!(std::ptr::eq(output.provider(), left_provider.as_ref()));
    assert!(!std::ptr::eq(output.provider(), right_provider.as_ref()));
    assert_eq!(left_provider.commit_count.load(Ordering::Relaxed), 1);
    assert_eq!(left_provider.postcommit_queries.load(Ordering::Relaxed), 0);
    assert_eq!(
        [
            left_provider.identity_queries.load(Ordering::Relaxed),
            left_provider.style_queries.load(Ordering::Relaxed),
            left_provider.algebra_queries.load(Ordering::Relaxed),
            left_provider.coefficient_queries.load(Ordering::Relaxed),
            left_provider.f_queries.load(Ordering::Relaxed),
            left_provider.r_queries.load(Ordering::Relaxed),
        ],
        admission_queries
    );
    for counter in [
        &right_provider.identity_queries,
        &right_provider.style_queries,
        &right_provider.algebra_queries,
        &right_provider.coefficient_queries,
        &right_provider.f_queries,
        &right_provider.r_queries,
        &right_provider.postcommit_queries,
    ] {
        assert_eq!(counter.load(Ordering::Relaxed), 0);
    }
}

#[test]
fn checked_generic_cat_precedence_and_admission_failure_are_typed_nonpublishing() {
    // What: admission stamps, runtime, cat arguments, then output admission
    // reject in order; every failure leaves both admitted input payloads alone.
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let other_runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(123));
    let equal = Arc::new(CheckedOnlyToy::new(123));
    let wrong = Arc::new(CheckedOnlyToy::new(1));
    let leg = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 1)]).unwrap();
    let equal_leg = GradedSpace::try_new(Arc::clone(&equal), [(Label::X, 1)]).unwrap();
    let wrong_leg = GradedSpace::try_new(Arc::clone(&wrong), [(Label::X, 1)]).unwrap();
    let lhs: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&leg], |_, indices| {
            1.0 + indices.iter().sum::<usize>() as f64
        })
        .unwrap();
    let valid_rhs: TensorMap<_, f64> =
        TensorMap::from_subblock_fn(&runtime, [&equal_leg, &equal_leg], [&equal_leg], |_, _| 2.0)
            .unwrap();
    let wrong_identity: TensorMap<_, f64> = TensorMap::zeros(
        &other_runtime,
        [&wrong_leg, &wrong_leg],
        [&wrong_leg, &wrong_leg],
    )
    .unwrap();
    let wrong_runtime: TensorMap<_, f64> = TensorMap::zeros(
        &other_runtime,
        [&equal_leg, &equal_leg],
        [&equal_leg, &equal_leg],
    )
    .unwrap();
    let bad_arguments: TensorMap<_, f64> =
        TensorMap::zeros(&runtime, [&equal_leg, &equal_leg], [&equal_leg, &equal_leg]).unwrap();
    let lhs_before = lhs.dense_data().unwrap().to_vec();
    let rhs_before = valid_rhs.dense_data().unwrap().to_vec();
    // See `forget_cached_structures`: this tag is this test's alone.
    forget_cached_structures();
    provider.fail_algebra.store(true, Ordering::Relaxed);
    for counter in [
        &provider.identity_queries,
        &provider.style_queries,
        &provider.algebra_queries,
        &provider.coefficient_queries,
        &provider.f_queries,
        &provider.r_queries,
    ] {
        counter.store(0, Ordering::Relaxed);
    }
    provider.reset_commit_spy();

    assert!(matches!(
        lhs.cat(&wrong_identity, Side::Domain),
        Err(GenericTensorError::Facade(
            tenet::typed::Error::RuleMismatch
        ))
    ));
    assert!(matches!(
        lhs.cat(&wrong_runtime, Side::Domain),
        Err(GenericTensorError::Facade(
            tenet::typed::Error::RuntimeMismatch
        ))
    ));
    assert!(matches!(
        lhs.cat(&bad_arguments, Side::Domain),
        Err(GenericTensorError::Facade(
            tenet::typed::Error::InvalidArgument(_)
        ))
    ));
    assert_eq!(provider.identity_queries.load(Ordering::Relaxed), 0);
    assert_eq!(provider.algebra_queries.load(Ordering::Relaxed), 0);

    assert!(matches!(
        lhs.cat(&valid_rhs, Side::Domain),
        Err(GenericTensorError::Structure(
            CheckedGenericStructureError::Provider(ToyError::Algebra)
        ))
    ));
    assert_eq!(provider.commit_count.load(Ordering::Relaxed), 0);
    assert_eq!(lhs.dense_data().unwrap(), lhs_before);
    assert_eq!(valid_rhs.dense_data().unwrap(), rhs_before);
}

#[cfg(feature = "racah-generated")]
fn sun_cat_marker(trees: &tenet::typed::BlockFusionTrees<Vec<i64>>) -> usize {
    trees
        .codomain_vertices()
        .iter()
        .enumerate()
        .map(|(index, vertex)| (index + 1) * 100 * vertex.get())
        .chain(
            trees
                .domain_vertices()
                .iter()
                .enumerate()
                .map(|(index, vertex)| (index + 1) * 1_000 * vertex.get()),
        )
        .sum()
}

#[cfg(feature = "racah-generated")]
fn assert_sun_cat_values<D>(
    output: &TensorMap<tenet::sector::SUNFusionRule, D>,
    lhs: &TensorMap<tenet::sector::SUNFusionRule, D>,
    rhs: &TensorMap<tenet::sector::SUNFusionRule, D>,
    changed_axis: usize,
    lhs_extent: usize,
    value: impl Fn(usize) -> D,
) where
    D: Copy + fmt::Debug + PartialEq + tenet::typed::TensorScalar,
{
    let mut saw_mu_two = false;
    for output_index in 0..output.subblock_count() {
        let trees = output.subblock_fusion_trees(output_index).unwrap();
        saw_mu_two |= trees
            .codomain_vertices()
            .iter()
            .chain(trees.domain_vertices())
            .any(|vertex| vertex.get() == 2);
        assert!((0..lhs.subblock_count())
            .any(|index| lhs.subblock_fusion_trees(index).unwrap() == trees));
        assert!((0..rhs.subblock_count())
            .any(|index| rhs.subblock_fusion_trees(index).unwrap() == trees));
        let block = output.subblock(output_index).unwrap();
        let elements = block.shape().iter().product::<usize>();
        for linear in 0..elements {
            let mut remainder = linear;
            let mut indices = Vec::with_capacity(block.shape().len());
            let mut position = block.offset();
            for (&extent, &stride) in block.shape().iter().zip(block.strides()) {
                let index = remainder % extent;
                remainder /= extent;
                indices.push(index);
                position += index * stride;
            }
            let (base, local_changed) = if indices[changed_axis] < lhs_extent {
                (10_000, indices[changed_axis])
            } else {
                (20_000, indices[changed_axis] - lhs_extent)
            };
            indices[changed_axis] = local_changed;
            let index_marker = indices
                .iter()
                .enumerate()
                .map(|(axis, index)| (axis + 1) * index)
                .sum::<usize>();
            assert_eq!(
                output.dense_data().unwrap()[position],
                value(base + sun_cat_marker(&trees) + index_marker)
            );
        }
    }
    assert!(saw_mu_two, "SU(N) cat fixture must carry a μ=2 full key");
}

#[cfg(feature = "racah-generated")]
fn assert_sun_cat_case<D>(n: usize, label: Vec<i64>, value: impl Fn(usize) -> D + Copy)
where
    D: Copy + fmt::Debug + PartialEq + tenet::typed::TensorScalar,
{
    use tenet::sector::SUNFusionRule;

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let left_provider = Arc::new(SUNFusionRule::new(n).unwrap());
    let right_provider = Arc::new(SUNFusionRule::new(n).unwrap());
    let left_common =
        GradedSpace::try_new(Arc::clone(&left_provider), [(label.clone(), 1)]).unwrap();
    let right_common =
        GradedSpace::try_new(Arc::clone(&right_provider), [(label.clone(), 1)]).unwrap();
    let left_changed =
        GradedSpace::try_new(Arc::clone(&left_provider), [(label.clone(), 1)]).unwrap();
    let right_changed =
        GradedSpace::try_new(Arc::clone(&right_provider), [(label.clone(), 2)]).unwrap();
    let fill = |base, trees: &tenet::typed::BlockFusionTrees<Vec<i64>>, indices: &[usize]| {
        value(
            base + sun_cat_marker(trees)
                + indices
                    .iter()
                    .enumerate()
                    .map(|(axis, index)| (axis + 1) * index)
                    .sum::<usize>(),
        )
    };

    let domain_lhs: TensorMap<_, D> = TensorMap::from_subblock_fn(
        &runtime,
        [&left_common, &left_common],
        [&left_changed],
        |trees, indices| fill(10_000, trees, indices),
    )
    .unwrap();
    let domain_rhs: TensorMap<_, D> = TensorMap::from_subblock_fn(
        &runtime,
        [&right_common, &right_common],
        [&right_changed],
        |trees, indices| fill(20_000, trees, indices),
    )
    .unwrap();
    let domain = domain_lhs.cat(&domain_rhs, Side::Domain).unwrap();
    assert!(std::ptr::eq(domain.provider(), left_provider.as_ref()));
    assert!(!std::ptr::eq(domain.provider(), right_provider.as_ref()));
    assert_eq!(domain.domain()[0].degeneracy(&label).unwrap(), 3);
    assert_sun_cat_values(&domain, &domain_lhs, &domain_rhs, 2, 1, value);
    let lazy_domain = domain_lhs
        .adjoint()
        .unwrap()
        .cat(&domain_rhs.adjoint().unwrap(), Side::Codomain)
        .unwrap();
    assert_eq!(
        lazy_domain.dense_data().unwrap(),
        domain
            .adjoint()
            .unwrap()
            .materialize()
            .unwrap()
            .dense_data()
            .unwrap()
    );

    let codomain_lhs: TensorMap<_, D> = TensorMap::from_subblock_fn(
        &runtime,
        [&left_changed],
        [&left_common, &left_common],
        |trees, indices| fill(10_000, trees, indices),
    )
    .unwrap();
    let codomain_rhs: TensorMap<_, D> = TensorMap::from_subblock_fn(
        &runtime,
        [&right_changed],
        [&right_common, &right_common],
        |trees, indices| fill(20_000, trees, indices),
    )
    .unwrap();
    let codomain = codomain_lhs.cat(&codomain_rhs, Side::Codomain).unwrap();
    assert!(std::ptr::eq(codomain.provider(), left_provider.as_ref()));
    assert_eq!(codomain.codomain()[0].degeneracy(&label).unwrap(), 3);
    assert_sun_cat_values(&codomain, &codomain_lhs, &codomain_rhs, 0, 1, value);
    let lazy_codomain = codomain_lhs
        .adjoint()
        .unwrap()
        .cat(&codomain_rhs.adjoint().unwrap(), Side::Domain)
        .unwrap();
    assert_eq!(
        lazy_codomain.dense_data().unwrap(),
        codomain
            .adjoint()
            .unwrap()
            .materialize()
            .unwrap()
            .dense_data()
            .unwrap()
    );
}

#[cfg(feature = "racah-generated")]
#[test]
fn sun_checked_generic_cat_covers_both_directions_dtypes_and_mu_two_keys() {
    // What: exact TensorKit direct-sum slab values, μ=2 full-key matching,
    // distinct equal-identity Arcs, left authority, and lazy-adjoint parity.
    for (n, label) in [(3, vec![1, 1]), (4, vec![1, 0, 1])] {
        assert_sun_cat_case(n, label.clone(), |value| value as f64);
        assert_sun_cat_case(n, label, |value| {
            Complex64::new(value as f64, -(value as f64))
        });
    }
}

#[cfg(feature = "racah-generated")]
#[test]
fn sun_adjoint_multiplicity_transforms_round_trip_labels_vertices_and_payload() {
    use tenet::sector::SUNFusionRule;

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    for (n, adjoint) in [(3, vec![1, 1]), (4, vec![1, 0, 1])] {
        let provider = Arc::new(SUNFusionRule::new(n).unwrap());
        let leg = GradedSpace::try_new(Arc::clone(&provider), [(adjoint.clone(), 1)]).unwrap();
        let tensor: TensorMap<_, f64> =
            TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&leg], |trees, _| {
                trees.codomain_vertices()[0].get() as f64
            })
            .unwrap();
        assert_eq!(tensor.subblock_count(), 2);
        for index in 0..2 {
            let trees = tensor.subblock_fusion_trees(index).unwrap();
            assert_eq!(trees.coupled(), &adjoint);
            assert_eq!(
                trees.codomain_uncoupled(),
                &[adjoint.clone(), adjoint.clone()]
            );
            assert_eq!(trees.domain_uncoupled(), std::slice::from_ref(&adjoint));
            assert_eq!(trees.codomain_vertices()[0].get(), index + 1);
            assert_eq!(tensor.subblock(index).unwrap().shape(), &[1, 1, 1]);
        }
        assert_eq!(tensor.dense_data().unwrap(), &[1.0, 2.0]);

        let identity: TensorMap<_, f64> =
            TensorMap::from_subblock_fn(&runtime, [&leg], [&leg], |_, _| 1.0).unwrap();
        for output in [
            tensor
                .contract(
                    &identity,
                    &ContractSpec {
                        lhs: &[2],
                        rhs: &[0],
                        codomain: &[0, 1],
                        domain: &[2],
                    },
                )
                .unwrap(),
            tensor.compose(&identity).unwrap(),
        ] {
            assert!(std::ptr::eq(output.provider(), provider.as_ref()));
            assert_eq!(output.dense_data().unwrap(), tensor.dense_data().unwrap());
            for index in 0..tensor.subblock_count() {
                assert_eq!(
                    output.subblock_fusion_trees(index).unwrap(),
                    tensor.subblock_fusion_trees(index).unwrap()
                );
            }
        }

        let product = tensor.otimes(&tensor).unwrap();
        assert!(std::ptr::eq(product.provider(), provider.as_ref()));
        let (expected_len, expected_sum, expected_weighted, expected_prefix): (
            usize,
            f64,
            f64,
            &[f64],
        ) = match n {
            3 => (
                145,
                9.468_841_418_575_323,
                39.231_504_693_264_13,
                &[
                    0.0,
                    1.0,
                    2.0,
                    2.0,
                    4.0,
                    0.0,
                    0.0,
                    0.0,
                    0.353_553_390_593_273_6,
                    0.707_106_781_186_547_2,
                    0.0,
                    0.857_142_857_142_857,
                ],
            ),
            4 => (
                245,
                8.608_165_620_335_726,
                -1.317_392_645_553_582,
                &[
                    0.0,
                    0.0,
                    1.0,
                    2.0,
                    2.0,
                    4.0,
                    0.0,
                    0.0,
                    0.0,
                    0.0,
                    0.338_873_675_850_995_87,
                    0.677_747_351_701_991_7,
                ],
            ),
            _ => unreachable!(),
        };
        assert_eq!(product.dense_data().unwrap().len(), expected_len);
        let sum = product.dense_data().unwrap().iter().sum::<f64>();
        let weighted = product
            .dense_data()
            .unwrap()
            .iter()
            .enumerate()
            .map(|(index, value)| (index + 1) as f64 * value)
            .sum::<f64>();
        assert!((sum - expected_sum).abs() <= 1e-10);
        assert!((weighted - expected_weighted).abs() <= 1e-9);
        for (&actual, &expected) in product.dense_data().unwrap().iter().zip(expected_prefix) {
            assert!((actual - expected).abs() <= 1e-10);
        }
        let mut adjoint_root_vertices = Vec::new();
        for index in 0..product.subblock_count() {
            let trees = product.subblock_fusion_trees(index).unwrap();
            if trees.coupled() == &adjoint
                && product.dense_data().unwrap()[product.subblock(index).unwrap().offset()].abs()
                    > 1e-10
            {
                assert_eq!(trees.codomain_uncoupled(), vec![adjoint.clone(); 4]);
                assert_eq!(trees.domain_uncoupled(), vec![adjoint.clone(); 2]);
                adjoint_root_vertices.push(trees.domain_vertices().last().unwrap().get());
            }
        }
        adjoint_root_vertices.sort_unstable();
        adjoint_root_vertices.dedup();
        assert_eq!(adjoint_root_vertices, [1, 2]);

        let snapshot = |tensor: &TensorMap<SUNFusionRule, f64>| {
            (0..tensor.subblock_count())
                .map(|index| tensor.subblock_fusion_trees(index).unwrap())
                .collect::<Vec<_>>()
        };
        let source_snapshot = snapshot(&tensor);
        for restored in [
            tensor
                .permute(&[1, 0], &[2])
                .unwrap()
                .permute(&[1, 0], &[2])
                .unwrap(),
            tensor
                .braid(&[0, 2], &[1], &[0, 1, 2])
                .unwrap()
                .braid(&[0, 2], &[1], &[0, 1, 2])
                .unwrap(),
            tensor.repartition(1).unwrap().repartition(2).unwrap(),
            tensor
                .transpose(&[2], &[1, 0])
                .unwrap()
                .transpose(&[2, 1], &[0])
                .unwrap(),
        ] {
            assert!(std::ptr::eq(restored.provider(), provider.as_ref()));
            assert_eq!(snapshot(&restored), source_snapshot);
            for (actual, expected) in restored
                .dense_data()
                .unwrap()
                .iter()
                .zip(tensor.dense_data().unwrap())
            {
                assert!((actual - expected).abs() <= 1e-10);
            }
        }
    }
}

#[cfg(feature = "racah-generated")]
#[test]
fn sun_checked_generic_transforms_reuse_the_runtime_completed_store() {
    use tenet::sector::SUNFusionRule;

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    for (n, adjoint) in [(3, vec![1, 1]), (4, vec![1, 0, 1])] {
        let provider = Arc::new(SUNFusionRule::new(n).unwrap());
        let leg = GradedSpace::try_new(Arc::clone(&provider), [(adjoint, 1)]).unwrap();
        let source: TensorMap<_, f64> =
            TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&leg], |trees, _| {
                trees.codomain_vertices()[0].get() as f64
            })
            .unwrap();

        for operation in ["permute", "braid", "repartition"] {
            runtime.clear_tree_transform_cache();
            let apply = |tensor: &TensorMap<SUNFusionRule, f64>| match operation {
                "permute" => tensor.permute(&[1, 0], &[2]),
                "braid" => tensor.braid(&[1, 0], &[2], &[0, 1, 2]),
                "repartition" => tensor.repartition(1),
                _ => unreachable!(),
            };
            let first = apply(&source).unwrap();
            let cold = runtime.tree_transform_cache_info().structures;
            let repeated = apply(&source).unwrap();
            let warm = runtime.tree_transform_cache_info().structures;

            assert_eq!(cold.entries(), 1);
            assert_eq!(cold.misses(), 1);
            assert_eq!(warm.entries(), 1);
            assert_eq!(warm.misses(), 1);
            assert_eq!(warm.hits(), 1);
            assert_eq!(repeated.dense_data().unwrap(), first.dense_data().unwrap());
            assert!(std::ptr::eq(first.provider(), provider.as_ref()));
            assert!(std::ptr::eq(repeated.provider(), provider.as_ref()));
            for index in 0..first.subblock_count() {
                assert_eq!(
                    repeated.subblock_fusion_trees(index).unwrap(),
                    first.subblock_fusion_trees(index).unwrap()
                );
            }
        }
    }
}

/// Rank 2+2 checked fixture: `X (x) X -> X` carries outer multiplicity two,
/// the coupled sector ranges over `{Vacuum, X}`, degeneracies two and three.
fn checked_multiplicity_lazy_fixture(
    runtime: &Runtime,
    provider: &Arc<CheckedOnlyToy>,
) -> TensorMap<CheckedOnlyToy, Complex64> {
    let x = GradedSpace::try_new(Arc::clone(provider), [(Label::X, 2)]).unwrap();
    let mixed =
        GradedSpace::try_new(Arc::clone(provider), [(Label::Vacuum, 1), (Label::X, 3)]).unwrap();
    let tensor =
        TensorMap::from_subblock_fn(runtime, [&x, &x], [&x, &mixed], lazy_oracle_value).unwrap();
    let coupled: std::collections::BTreeSet<_> = (0..tensor.subblock_count())
        .map(|index| *tensor.subblock_fusion_trees(index).unwrap().coupled())
        .collect();
    assert_eq!(coupled.len(), 2);
    assert!((0..tensor.subblock_count()).any(|index| {
        tensor
            .subblock_fusion_trees(index)
            .unwrap()
            .codomain_vertices()[0]
            .get()
            == 2
    }));
    tensor
}

/// Asserts `lazy.data()` against the literal pre-#1201 formula, builds an
/// Owned twin from that literal payload, and checks that every listed
/// transform gives the same blocks (or the same error) on both. `$ops` is a
/// closure `(lazy, owned) -> [(name, Result, Result); N]`.
macro_rules! assert_checked_lazy_adjoint_matches_literal {
    ($parent:expr, $conj:expr, $close:expr, $ops:expr) => {{
        let parent = $parent;
        let lazy = parent.adjoint().unwrap();
        let parent_snapshot = snapshot!(parent);
        let lazy_snapshot = snapshot!(lazy);
        let literal = common::literal_adjoint_payload(&parent_snapshot, &lazy_snapshot, $conj);
        assert_eq!(
            literal.len(),
            lazy.materialize().unwrap().dense_data().unwrap().len()
        );
        for (actual, expected) in lazy
            .materialize()
            .unwrap()
            .dense_data()
            .unwrap()
            .iter()
            .zip(&literal)
        {
            assert!($close(*actual, *expected), "{actual:?} != {expected:?}");
        }
        let codomain = lazy.codomain();
        let domain = lazy.domain();
        let owned =
            TensorMap::from_subblock_fn(parent.runtime(), &codomain, &domain, |trees, indices| {
                let (_, geometry) = lazy_snapshot
                    .blocks
                    .iter()
                    .find(|(candidate, _)| candidate == trees)
                    .unwrap();
                literal[common::linear(geometry, indices)]
            })
            .unwrap();
        common::assert_same_tensor(&snapshot!(owned), &lazy_snapshot, $close);

        let mut succeeded = 0usize;
        for (name, actual, expected) in $ops(&lazy, &owned) {
            match (actual, expected) {
                (Ok(actual), Ok(expected)) => {
                    succeeded += 1;
                    assert!(std::ptr::eq(actual.provider(), parent.provider()));
                    common::assert_same_tensor(&snapshot!(actual), &snapshot!(expected), $close);
                }
                (Err(actual), Err(expected)) => {
                    assert_eq!(format!("{actual:?}"), format!("{expected:?}"), "{name}")
                }
                (actual, expected) => panic!("{name}: lazy {actual:?} vs owned {expected:?}"),
            }
        }
        succeeded
    }};
}

#[test]
fn checked_multiplicity_lazy_adjoint_matches_the_literal_kernel_for_real_and_complex() {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(CheckedOnlyToy::new(0));
    // The toy's F-symbols are the identity on `e == f` and zero otherwise, so
    // most recouplings are unrepresentable and fail identically for the lazy
    // and the Owned input (error parity is asserted); the real SU(3) sibling
    // below covers every transform. Bends on a one-sided tree do succeed and
    // exercise the checked lane's lazy-input materialization.
    type ToyStep<D> = (
        &'static str,
        Result<TensorMap<CheckedOnlyToy, D>, GenericTensorError<ToyError>>,
        Result<TensorMap<CheckedOnlyToy, D>, GenericTensorError<ToyError>>,
    );
    fn two_sided_ops<D: tenet::typed::TensorScalar>(
        lazy: &TensorMap<CheckedOnlyToy, D>,
        owned: &TensorMap<CheckedOnlyToy, D>,
    ) -> [ToyStep<D>; 5] {
        [
            (
                "permute",
                lazy.permute(&[1, 0], &[2, 3]),
                owned.permute(&[1, 0], &[2, 3]),
            ),
            (
                "braid",
                lazy.braid(&[1, 0], &[2, 3], &[1, 0, 2, 3]),
                owned.braid(&[1, 0], &[2, 3], &[1, 0, 2, 3]),
            ),
            ("repartition", lazy.repartition(1), owned.repartition(1)),
            (
                "full transpose",
                lazy.transpose(&[3, 2], &[1, 0]),
                owned.transpose(&[3, 2], &[1, 0]),
            ),
            (
                "transpose",
                lazy.transpose(&[1, 3], &[0, 2]),
                owned.transpose(&[1, 3], &[0, 2]),
            ),
        ]
    }
    // Lazy space `[] <- X, X, X`.
    fn one_sided_ops<D: tenet::typed::TensorScalar>(
        lazy: &TensorMap<CheckedOnlyToy, D>,
        owned: &TensorMap<CheckedOnlyToy, D>,
    ) -> [ToyStep<D>; 5] {
        [
            (
                "permute",
                lazy.permute(&[], &[1, 0, 2]),
                owned.permute(&[], &[1, 0, 2]),
            ),
            (
                "braid",
                lazy.braid(&[], &[1, 0, 2], &[0, 1, 2]),
                owned.braid(&[], &[1, 0, 2], &[0, 1, 2]),
            ),
            ("repartition", lazy.repartition(1), owned.repartition(1)),
            (
                "full transpose",
                lazy.transpose(&[2, 1, 0], &[]),
                owned.transpose(&[2, 1, 0], &[]),
            ),
            (
                "transpose",
                lazy.transpose(&[2], &[0, 1]),
                owned.transpose(&[2], &[0, 1]),
            ),
        ]
    }

    let two_sided = checked_multiplicity_lazy_fixture(&runtime, &provider);
    assert!(two_sided
        .dense_data()
        .unwrap()
        .iter()
        .any(|value| value.im != 0.0));
    assert_checked_lazy_adjoint_matches_literal!(
        two_sided.clone(),
        |z: Complex64| z.conj(),
        lazy_close_c64,
        two_sided_ops
    );
    assert_checked_lazy_adjoint_matches_literal!(
        two_sided.re(),
        |x: f64| x,
        lazy_close_f64,
        two_sided_ops
    );

    let x = GradedSpace::try_new(Arc::clone(&provider), [(Label::X, 2)]).unwrap();
    let one_sided =
        TensorMap::from_subblock_fn(&runtime, [&x, &x, &x], [], lazy_oracle_value).unwrap();
    assert!((0..one_sided.subblock_count()).any(|index| {
        one_sided
            .subblock_fusion_trees(index)
            .unwrap()
            .codomain_vertices()[0]
            .get()
            == 2
    }));
    let complex_succeeded = assert_checked_lazy_adjoint_matches_literal!(
        one_sided.clone(),
        |z: Complex64| z.conj(),
        lazy_close_c64,
        one_sided_ops
    );
    let real_succeeded = assert_checked_lazy_adjoint_matches_literal!(
        one_sided.re(),
        |x: f64| x,
        lazy_close_f64,
        one_sided_ops
    );
    assert!(complex_succeeded >= 2 && real_succeeded >= 2);
}

/// Real SU(3) multiplicity: all five transforms on a lazy adjoint against the
/// literal-payload Owned twin.
#[cfg(feature = "racah-generated")]
#[test]
fn sun_lazy_adjoint_matches_the_literal_kernel_under_all_transforms() {
    use tenet::sector::SUNFusionRule;

    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(SUNFusionRule::new(3).unwrap());
    let adjoint = vec![1, 1];
    let leg = GradedSpace::try_new(Arc::clone(&provider), [(adjoint.clone(), 2)]).unwrap();
    let other =
        GradedSpace::try_new(Arc::clone(&provider), [(vec![0, 0], 1), (adjoint, 1)]).unwrap();
    let complex =
        TensorMap::from_subblock_fn(&runtime, [&leg, &leg], [&other, &leg], |trees, indices| {
            let tree = (format!("{trees:?}").bytes().fold(0u32, |acc, byte| {
                acc.wrapping_mul(31).wrapping_add(byte as u32)
            }) % 97) as f64;
            let mut re = tree;
            let mut im = -0.5 * tree + 0.25;
            for (axis, &index) in indices.iter().enumerate() {
                re += (index as f64 + 1.0) * (axis as f64 + 1.0);
                im += (index as f64 + 1.0) * (axis as f64 + 1.0) * (axis as f64 + 1.0) * 0.5;
            }
            Complex64::new(re, im)
        })
        .unwrap();
    assert!((0..complex.subblock_count()).any(|index| {
        complex
            .subblock_fusion_trees(index)
            .unwrap()
            .codomain_vertices()[0]
            .get()
            == 2
    }));
    type SunStep<D> = (
        &'static str,
        Result<TensorMap<SUNFusionRule, D>, GenericTensorError<tenet::sector::SUNFusionRuleError>>,
        Result<TensorMap<SUNFusionRule, D>, GenericTensorError<tenet::sector::SUNFusionRuleError>>,
    );
    fn ops<D: tenet::typed::TensorScalar>(
        lazy: &TensorMap<SUNFusionRule, D>,
        owned: &TensorMap<SUNFusionRule, D>,
    ) -> [SunStep<D>; 5] {
        [
            (
                "permute",
                lazy.permute(&[1, 3], &[0, 2]),
                owned.permute(&[1, 3], &[0, 2]),
            ),
            (
                "braid",
                lazy.braid(&[1, 3], &[0, 2], &[3, 1, 2, 0]),
                owned.braid(&[1, 3], &[0, 2], &[3, 1, 2, 0]),
            ),
            ("repartition", lazy.repartition(1), owned.repartition(1)),
            (
                "full transpose",
                lazy.transpose(&[3, 2], &[1, 0]),
                owned.transpose(&[3, 2], &[1, 0]),
            ),
            (
                "transpose",
                lazy.transpose(&[1, 3], &[0, 2]),
                owned.transpose(&[1, 3], &[0, 2]),
            ),
        ]
    }
    let succeeded = assert_checked_lazy_adjoint_matches_literal!(
        complex.clone(),
        |z: Complex64| z.conj(),
        lazy_close_c64,
        ops
    );
    assert_eq!(succeeded, 5);
    let succeeded =
        assert_checked_lazy_adjoint_matches_literal!(complex.re(), |x: f64| x, lazy_close_f64, ops);
    assert_eq!(succeeded, 5);
}
