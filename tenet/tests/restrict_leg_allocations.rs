//! Allocation contract of `restrict_leg` and of the re-routed internal
//! network restriction (#1285).
//!
//! The contract is *not* a total call count: each call rebuilds the small
//! structural objects of the destination hom-space. What is pinned is that
//! the output payload is never zero-filled — its blocks tile it, so it is
//! allocated uninitialized and overwritten once (#1290) — and that everything
//! else is independent of the degeneracy dimensions — two tensors with the
//! same sector structure and different degeneracies must allocate the same
//! number of non-payload blocks.

use std::hint::black_box;
use std::sync::Arc;

use tenet::sector::TypedSectorAdmission;
use tenet::sector::{U1FusionRule, U1Irrep};
use tenet::typed::__network::{self, NetworkDegeneracyRestriction};
use tenet::typed::{GradedSpace, LegSelection, Runtime, TensorMap};
use tenet::typed::{StackedTensorMap, Svd};

#[path = "../../tests/support/counting_alloc.rs"]
mod counting_alloc;

#[global_allocator]
static ALLOCATOR: counting_alloc::CountingAllocator = counting_alloc::CountingAllocator;

#[derive(Debug)]
struct Measurement {
    allocations: usize,
    bytes: usize,
    /// Allocator-zeroed allocations of exactly the `payload_bytes` passed to
    /// `measure`.
    zeroed_payloads: u64,
}

fn measure(payload_bytes: usize, operation: impl FnOnce()) -> Measurement {
    let ((), allocs) = counting_alloc::measure_matching(payload_bytes..=payload_bytes, operation);
    Measurement {
        allocations: allocs.calls as usize,
        bytes: allocs.bytes as usize,
        zeroed_payloads: allocs.matched_zeroed_calls,
    }
}

fn u1(provider: &Arc<U1FusionRule>, pairs: &[(i32, usize)]) -> GradedSpace<U1FusionRule> {
    GradedSpace::try_new(
        Arc::clone(provider),
        pairs
            .iter()
            .map(|&(charge, degeneracy)| (U1Irrep::new(charge), degeneracy)),
    )
    .unwrap()
}

/// One `restrict_leg` on a leg whose degeneracies are `scale` times a base
/// shape: the measurement and the payload byte count for that scale.
fn restrict_measurement(scale: usize) -> (Measurement, usize) {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let leg = u1(
        &provider,
        &[(-1, 2 * scale), (0, 3 * scale), (1, 2 * scale)],
    );
    let other = u1(&provider, &[(-1, 1), (0, 2), (1, 1)]);
    let source: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&leg], [&other, &other], 41).unwrap();
    let selection = LegSelection::try_new(
        &leg,
        [
            (U1Irrep::new(-1), 0..scale),
            (U1Irrep::new(0), scale..3 * scale),
        ],
    )
    .unwrap();

    // Warm every structural cache the call can hit before measuring.
    let warm = source.restrict_leg(&[(0, &selection)]).unwrap();
    let payload_bytes = std::mem::size_of_val(warm.dense_data().unwrap());

    let mut output = None;
    let measurement = measure(payload_bytes, || {
        output = Some(black_box(source.restrict_leg(&[(0, &selection)]).unwrap()));
    });
    assert_eq!(
        output.unwrap().dense_data().unwrap(),
        warm.dense_data().unwrap()
    );
    (measurement, payload_bytes)
}

#[test]
fn restrict_leg_allocates_one_unfilled_payload_and_degeneracy_independent_scratch() {
    let _guard = counting_alloc::serial();
    let (small, small_bytes) = restrict_measurement(1);
    let (large, large_bytes) = restrict_measurement(8);
    assert!(large_bytes > small_bytes);

    for (measurement, bytes) in [(&small, small_bytes), (&large, large_bytes)] {
        assert_eq!(
            measurement.zeroed_payloads, 0,
            "no payload-sized zeroed allocation, got {measurement:?} for {bytes} bytes"
        );
    }
    // The block copy's scratch is inline (#1362) and the warm layout lookup
    // builds no key (#1367), so every call is the result's structural objects
    // or its payload. The start table is borrowed from the selection (#1561).
    assert_eq!(small.allocations, 8);
    // Structural work does not grow with the degeneracy dimensions. The byte
    // budget pins the payload to one buffer and rules out a second
    // payload-sized buffer taken through plain `alloc`/`realloc`.
    assert_eq!(small.allocations, large.allocations);
    assert_eq!(
        small.bytes - small_bytes,
        large.bytes - large_bytes,
        "non-payload bytes must not depend on the degeneracy dimensions: \
         {small:?} vs {large:?} bytes for payloads {small_bytes}/{large_bytes}",
        small = small.bytes,
        large = large.bytes
    );
}

/// One restriction of all three legs of a tensor whose degeneracies are
/// `scale` times a base shape: the measurement and the payload byte count.
/// `sequential` restricts one leg per call instead, the negative control.
fn three_axis_measurement(scale: usize, sequential: bool) -> (Measurement, usize) {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let leg = u1(
        &provider,
        &[(-1, 2 * scale), (0, 3 * scale), (1, 2 * scale)],
    );
    let dual = leg.try_dual().unwrap();
    let source: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&leg, &dual], [&leg], 53).unwrap();
    let on_leg = LegSelection::try_new(
        &leg,
        [
            (U1Irrep::new(-1), 0..scale),
            (U1Irrep::new(0), scale..3 * scale),
        ],
    )
    .unwrap();
    let on_dual = LegSelection::try_new(
        &dual,
        [
            (U1Irrep::new(1), scale..2 * scale),
            (U1Irrep::new(0), 0..2 * scale),
        ],
    )
    .unwrap();
    let set = [(2, &on_leg), (0, &on_leg), (1, &on_dual)];
    let restrict = || {
        if sequential {
            set.iter().fold(source.clone(), |tensor, &pair| {
                tensor.restrict_leg(&[pair]).unwrap()
            })
        } else {
            source.restrict_leg(&set).unwrap()
        }
    };

    let warm = restrict();
    let payload_bytes = std::mem::size_of_val(warm.dense_data().unwrap());
    let mut output = None;
    let measurement = measure(payload_bytes, || {
        output = Some(black_box(restrict()));
    });
    assert_eq!(
        output.unwrap().dense_data().unwrap(),
        warm.dense_data().unwrap()
    );
    (measurement, payload_bytes)
}

#[test]
fn restricting_three_legs_is_one_payload_pass() {
    let _guard = counting_alloc::serial();
    // What: `k` legs are restricted in one strided pass into one output
    // payload (#1561). Sequential one-leg passes would each allocate an
    // intermediate payload whose size grows with the degeneracies, so the
    // non-payload bytes would not stay fixed across scales.
    let (small, small_bytes) = three_axis_measurement(1, false);
    let (large, large_bytes) = three_axis_measurement(8, false);
    assert!(large_bytes > small_bytes);
    for (measurement, bytes) in [(&small, small_bytes), (&large, large_bytes)] {
        assert_eq!(
            measurement.zeroed_payloads, 0,
            "no payload-sized zeroed allocation, got {measurement:?} for {bytes} bytes"
        );
    }
    assert_eq!(small.allocations, large.allocations);
    assert_eq!(
        small.bytes - small_bytes,
        large.bytes - large_bytes,
        "only the output payload may grow with the degeneracies: \
         {small:?} vs {large:?} bytes for payloads {small_bytes}/{large_bytes}",
        small = small.bytes,
        large = large.bytes
    );

    // Negative control: the same three legs restricted one call at a time
    // allocate two intermediate payloads, so the assertion above would fail.
    let (small, small_bytes) = three_axis_measurement(1, true);
    let (large, large_bytes) = three_axis_measurement(8, true);
    assert_ne!(
        small.bytes - small_bytes,
        large.bytes - large_bytes,
        "sequential passes must show degeneracy-dependent non-payload bytes"
    );
}

#[test]
fn the_network_restriction_of_several_axes_fills_no_payload() {
    let _guard = counting_alloc::serial();
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let zero = U1Irrep::new(0);
    let rows = u1(&provider, &[(0, 6)]);
    let columns = u1(&provider, &[(0, 8)]);
    let source: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&rows], [&columns], 43).unwrap();
    let zero_id = TypedSectorAdmission::try_encode_label(provider.as_ref(), &zero).unwrap();
    let restrictions = [
        NetworkDegeneracyRestriction {
            effective_axis: 0,
            authority_sector: zero_id,
            range: 1..4,
            partner: false,
        },
        NetworkDegeneracyRestriction {
            effective_axis: 1,
            authority_sector: zero_id,
            range: 2..6,
            partner: false,
        },
    ];

    let warm = __network::network_restrict_degeneracies(&source, false, &restrictions).unwrap();
    let payload_bytes = std::mem::size_of_val(warm.dense_data().unwrap());
    assert_eq!(warm.dense_data().unwrap().len(), 3 * 4);

    let mut output = None;
    let measurement = measure(payload_bytes, || {
        output = Some(black_box(
            __network::network_restrict_degeneracies(&source, false, &restrictions).unwrap(),
        ));
    });
    assert_eq!(
        output.unwrap().dense_data().unwrap(),
        warm.dense_data().unwrap()
    );
    assert_eq!(
        measurement.zeroed_payloads, 0,
        "two restricted axes write one unfilled payload, got {measurement:?}"
    );
    assert!(measurement.bytes >= payload_bytes);
}

/// One compact two-leg `restrict_leg` on an `s : bond <- bond` whose degeneracies
/// are `scale` times a base shape, keeping a fixed prefix of each sector.
fn compact_restrict_measurement(scale: usize) -> Measurement {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let leg = u1(&provider, &[(-1, 2 * scale), (0, 3 * scale)]);
    let source: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&leg], [&leg], 47).unwrap();
    let Svd { s, .. } = source.svd_compact(&[0], &[1]).unwrap();
    let bond = s.domain()[0].clone();
    let selection =
        LegSelection::try_new(&bond, [(U1Irrep::new(-1), 0..2), (U1Irrep::new(0), 0..3)]).unwrap();

    let warm = s.restrict_leg(&[(0, &selection), (1, &selection)]).unwrap();
    assert!(
        tenet::expert::diagonal_spectrum(&warm).unwrap().is_some(),
        "a compact receiver must stay compact"
    );

    let mut output = None;
    // No dense payload to watch: callers compare only calls and bytes.
    let measurement = measure(0, || {
        output = Some(black_box(
            s.restrict_leg(&[(0, &selection), (1, &selection)]).unwrap(),
        ));
    });
    assert_eq!(
        tenet::expert::diagonal_spectrum(&output.unwrap()).unwrap(),
        tenet::expert::diagonal_spectrum(&warm).unwrap()
    );
    measurement
}

#[test]
fn compact_restrict_leg_costs_the_kept_values_and_nothing_per_discarded_one() {
    let _guard = counting_alloc::serial();
    // The kept prefix is the same in both; only the discarded tail grows. A
    // compact restriction must therefore cost exactly the same, which is the
    // `O(sum_c k'_c)` contract: no dense block is ever materialized.
    let small = compact_restrict_measurement(1);
    let large = compact_restrict_measurement(16);
    assert_eq!(small.allocations, large.allocations);
    assert_eq!(small.bytes, large.bytes);
}

#[test]
fn lazy_adjoint_add_and_materialization_fill_no_payload() {
    let _guard = counting_alloc::serial();
    // What: the owned outputs of a lazy-adjoint `add` and of the first
    // lazy-adjoint `data()` tile their storage, so neither zero-fills its
    // payload before overwriting every block (#1290). For `f64` the base
    // fill was `vec![0.0; len]`, an allocator-zeroed allocation.
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let leg = u1(&provider, &[(-1, 2), (0, 3), (1, 2)]);
    let other = u1(&provider, &[(-1, 1), (0, 2), (1, 3)]);
    let square: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&leg, &other], [&leg, &other], 53).unwrap();
    let partner: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&leg, &other], [&leg, &other], 59).unwrap();
    let lazy = square.adjoint().unwrap();
    let payload_bytes = std::mem::size_of_val(square.dense_data().unwrap());
    assert!(square.subblock_count() > 1);

    let mut sum = None;
    let add = measure(payload_bytes, || {
        sum = Some(black_box(lazy.axpby(0.5, &partner, -2.0).unwrap()));
    });
    assert_eq!(
        add.zeroed_payloads, 0,
        "lazy add zero-filled its payload: {add:?}"
    );

    let materialize = measure(payload_bytes, || {
        black_box(lazy.materialize().unwrap().dense_data().unwrap().len());
    });
    assert_eq!(
        materialize.zeroed_payloads, 0,
        "lazy materialization zero-filled its payload: {materialize:?}"
    );
    // Oracle: the elementwise sum over the materialized adjoint payload,
    // which shares the partner's logical layout.
    let expected: Vec<u64> = lazy
        .materialize()
        .unwrap()
        .dense_data()
        .unwrap()
        .iter()
        .zip(partner.dense_data().unwrap())
        .map(|(&x, &y)| (0.5 * x + -2.0 * y).to_bits())
        .collect();
    let actual: Vec<u64> = sum
        .unwrap()
        .dense_data()
        .unwrap()
        .iter()
        .map(|x| x.to_bits())
        .collect();
    assert_eq!(actual, expected);
}

/// Steady-state `restrict_leg` on `[leg, other] <- [leg, other]`: every
/// coupled sector has several row trees, so the destination blocks are
/// strided sub-matrices. Returns the measurement and payload bytes of one
/// warm call whose previous outputs were dropped.
fn steady_multi_row_restrict(scale: usize) -> (Measurement, usize) {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let leg = u1(
        &provider,
        &[(-1, 2 * scale), (0, 3 * scale), (1, 2 * scale)],
    );
    let other = u1(&provider, &[(-1, 1), (0, 2), (1, 1)]);
    let source: TensorMap<_, f64> =
        TensorMap::rand_with_seed(&runtime, [&leg, &other], [&leg, &other], 61).unwrap();
    let selection = LegSelection::try_new(
        &leg,
        [
            (U1Irrep::new(-1), 0..scale),
            (U1Irrep::new(0), scale..3 * scale),
        ],
    )
    .unwrap();
    let warm = source.restrict_leg(&[(0, &selection)]).unwrap();
    let expected = warm.dense_data().unwrap().to_vec();
    let payload_bytes = std::mem::size_of_val(warm.dense_data().unwrap());
    drop(warm);
    drop(black_box(source.restrict_leg(&[(0, &selection)]).unwrap()));
    let mut output = None;
    let measurement = measure(payload_bytes, || {
        output = Some(black_box(source.restrict_leg(&[(0, &selection)]).unwrap()));
    });
    assert_eq!(output.unwrap().dense_data().unwrap(), expected.as_slice());
    (measurement, payload_bytes)
}

#[test]
fn steady_state_restrict_leg_with_several_row_trees_pays_no_layout_proof() {
    let _guard = counting_alloc::serial();
    let (small, small_bytes) = steady_multi_row_restrict(1);
    let (large, large_bytes) = steady_multi_row_restrict(4);
    for (measurement, bytes) in [(&small, small_bytes), (&large, large_bytes)] {
        assert_eq!(
            measurement.zeroed_payloads, 0,
            "no payload-sized zeroed allocation, got {measurement:?} for {bytes} bytes"
        );
    }
    // origin/main (zero-filled output) measures 11 here. Proving the tiling
    // by compiling `coupled_sector_regions` on the per-call destination
    // wrapper measured 50: the proof must be an O(1) property recorded when
    // the canonical layout is built (#1290).
    assert!(
        small.allocations <= 11,
        "steady-state restrict_leg allocated {} times",
        small.allocations
    );
    assert_eq!(small.allocations, large.allocations);
}

/// One stacked `restrict_leg` over `members` members `[leg, other] <- [leg,
/// other]` (several row trees per coupled sector): the measurement of a warm
/// call and its payload bytes.
fn stacked_restrict_measurement(members: usize) -> (Measurement, usize) {
    let runtime = Runtime::builder().dense_threads(1).build().unwrap();
    let provider = Arc::new(U1FusionRule);
    let leg = u1(&provider, &[(-1, 2), (0, 3), (1, 2)]);
    let other = u1(&provider, &[(-1, 1), (0, 2), (1, 1)]);
    let tensors: Vec<TensorMap<_, f64>> = (0..members)
        .map(|seed| {
            TensorMap::rand_with_seed(&runtime, [&leg, &other], [&leg, &other], 67 + seed as u64)
                .unwrap()
        })
        .collect();
    let stack = StackedTensorMap::pack(&tensors).unwrap();
    let selection =
        LegSelection::try_new(&leg, [(U1Irrep::new(-1), 0..1), (U1Irrep::new(0), 1..3)]).unwrap();
    let warm = stack.restrict_leg(&[(0, &selection)]).unwrap();
    let payload_bytes =
        members * std::mem::size_of_val(warm.member(0).unwrap().dense_data().unwrap());
    drop(warm);
    let mut output = None;
    let measurement = measure(payload_bytes, || {
        output = Some(black_box(stack.restrict_leg(&[(0, &selection)]).unwrap()));
    });
    let output = output.unwrap();
    for (index, tensor) in tensors.iter().enumerate() {
        assert_eq!(
            output.member(index).unwrap().dense_data().unwrap(),
            tensor
                .restrict_leg(&[(0, &selection)])
                .unwrap()
                .dense_data()
                .unwrap()
        );
    }
    (measurement, payload_bytes)
}

#[test]
fn stacked_restrict_leg_allocates_one_unfilled_payload_independent_of_the_member_count() {
    let _guard = counting_alloc::serial();
    let (small, small_bytes) = stacked_restrict_measurement(2);
    let (large, large_bytes) = stacked_restrict_measurement(16);
    for (measurement, bytes) in [(&small, small_bytes), (&large, large_bytes)] {
        assert_eq!(
            measurement.zeroed_payloads, 0,
            "no payload-sized zeroed allocation, got {measurement:?} for {bytes} bytes"
        );
    }
    // One output buffer of `B L'` elements; everything else is the result's
    // structural objects, which do not depend on `B`.
    assert_eq!(small.allocations, large.allocations);
    assert_eq!(
        small.bytes - small_bytes,
        large.bytes - large_bytes,
        "non-payload bytes must not depend on the member count"
    );
}
