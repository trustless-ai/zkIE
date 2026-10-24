//! Minimal WHIR multilinear PCS wrapper over Goldilocks.
//!
//! Exposes a clean commit -> prescribed-point open -> verify cycle for a single
//! flat multilinear extension (a `Vec<Goldilocks>` of length `2^d`). The opening
//! point is caller-chosen (base-field coordinates) and is embedded into the
//! degree-2 extension field internally, which is exactly the binding a GKR
//! matmul verifier needs for the two sum-check evaluations it would otherwise
//! recompute in `O(k)`.

// Loop bodies in this module index several buffers from one loop counter
// (bit-indexing, `pos * h + d` layouts, interleaved field arithmetic). The
// iterator rewrites this lint suggests read worse here and, in the FFT/logUp
// kernels, would reorder field operations; the indexed form is deliberate.
#![allow(clippy::needless_range_loop)]

/// Global count of FRI opening proofs across all Whir instances (batch Whirs are
/// transient, so per-instance stats do not accumulate). Used for telemetry.
static GLOBAL_OPEN_COUNT: std::sync::atomic::AtomicU64 = std::sync::atomic::AtomicU64::new(0);

/// Total number of FRI opening proofs produced so far in this process.
pub fn global_open_count() -> u64 {
    GLOBAL_OPEN_COUNT.load(std::sync::atomic::Ordering::Relaxed)
}

use p3_challenger::DuplexChallenger;
use p3_commit::MultilinearPcs;
use p3_dft::Radix2DFTSmallBatch;
use p3_field::extension::BinomialExtensionField;
use p3_field::{ExtensionField, Field};
use p3_goldilocks::{Goldilocks, Poseidon2Goldilocks};
use p3_matrix::dense::RowMajorMatrix;
use p3_merkle_tree::MerkleTreeMmcs;
use p3_multilinear_util::point::Point;
use p3_sumcheck::layout::{Layout as _, SuffixProver, Table};
use p3_sumcheck::{OpeningBatch, PointSchedule, PrescribedPointPcs, TableShape, TableSpec};
use p3_symmetric::{PaddingFreeSponge, TruncatedPermutation};
use p3_whir::fiat_shamir::domain_separator::DomainSeparator;
use p3_whir::parameters::{
    FoldingFactor, ProtocolParameters, SecurityAssumption, WhirConfig, WhirConfigError,
};
use p3_whir::pcs::prover::WhirProver;
use rand::rngs::SmallRng;
use rand::SeedableRng;

type F = Goldilocks;
type EF = BinomialExtensionField<F, 2>;
type Perm = Poseidon2Goldilocks<16>;
type MerkleHash = PaddingFreeSponge<Perm, 16, 8, 8>;
type MerkleCompress = TruncatedPermutation<Perm, 2, 8, 16>;
type MyChallenger = DuplexChallenger<F, Perm, 16, 8>;
type PackedF = <F as Field>::Packing;
type MyLayout = SuffixProver<F, EF>;

type CpuMmcs = MerkleTreeMmcs<PackedF, PackedF, MerkleHash, MerkleCompress, 2, 8>;
type CpuDft = Radix2DFTSmallBatch<F>;

// The DFT and Merkle engines are swappable at the type level. Without the
// `cuda` feature these are the pure-CPU p3 implementations. With it, they
// are runtime-dispatched enums: measured on the 64-core dev box the GPU
// path is launch/transfer-bound and *slower* than 64-thread rayon for the
// 200M proof's many small commitments (548.7s vs 402.5s end-to-end), so the
// CPU engines stay the default and the GPU path is opt-in via
// `ZKIE_CUDA=1` (e.g. for thread-constrained deployments, where a 2^22
// commit measures 25.9x faster than single-threaded CPU).
#[cfg(feature = "cuda")]
mod backend {
    use super::*;
    use p3_commit::Mmcs as _;
    use p3_dft::TwoAdicSubgroupDft;
    use p3_matrix::Matrix as _;

    /// Whether the GPU engines should be used for this process.
    pub fn use_cuda() -> bool {
        matches!(std::env::var("ZKIE_CUDA"), Ok(v) if v == "1" || v == "true")
    }

    /// Resolve a per-engine override (`ZKIE_CUDA_DFT` / `ZKIE_CUDA_MMCS`),
    /// falling back to the global `ZKIE_CUDA` switch. This lets autotuning
    /// pin the DFT and Merkle engines independently of each other.
    fn pick_backend(name: &str, fallback: bool) -> bool {
        match std::env::var(name).ok().as_deref() {
            Some("1") | Some("true") | Some("cuda") => true,
            Some("0") | Some("false") | Some("cpu") => false,
            _ => fallback,
        }
    }

    pub fn use_cuda_dft() -> bool {
        pick_backend("ZKIE_CUDA_DFT", use_cuda())
    }

    pub fn use_cuda_mmcs() -> bool {
        pick_backend("ZKIE_CUDA_MMCS", use_cuda())
    }

    pub enum DftBackend {
        Cpu(CpuDft),
        #[cfg(feature = "cuda")]
        Cuda(crate::pcs::dft_cuda::CudaDft),
    }

    impl Clone for DftBackend {
        fn clone(&self) -> Self {
            match self {
                Self::Cpu(d) => Self::Cpu(d.clone()),
                #[cfg(feature = "cuda")]
                Self::Cuda(d) => Self::Cuda(d.clone()),
            }
        }
    }

    impl Default for DftBackend {
        fn default() -> Self {
            Self::Cpu(CpuDft::default())
        }
    }

    impl TwoAdicSubgroupDft<F> for DftBackend {
        type Evaluations = RowMajorMatrix<F>;

        fn dft_batch(&self, mat: RowMajorMatrix<F>) -> Self::Evaluations {
            match self {
                Self::Cpu(d) => d.dft_batch(mat),
                #[cfg(feature = "cuda")]
                Self::Cuda(d) => d.dft_batch(mat),
            }
        }
    }

    pub enum MmcsBackend {
        Cpu(CpuMmcs),
        #[cfg(feature = "cuda")]
        Cuda(crate::pcs::merkle_cuda::CudaMerkleTreeMmcs),
    }

    impl Clone for MmcsBackend {
        fn clone(&self) -> Self {
            match self {
                Self::Cpu(m) => Self::Cpu(m.clone()),
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => Self::Cuda(m.clone()),
            }
        }
    }

    impl p3_commit::Mmcs<F> for MmcsBackend {
        type ProverData<M> = p3_merkle_tree::MerkleTree<F, F, M, 2, 8>;
        type Commitment = p3_symmetric::MerkleCap<F, [F; 8]>;
        type Proof = Vec<[F; 8]>;
        type MultiProof = p3_merkle_tree::PrunedMerklePaths<F, 8>;
        type Error = p3_merkle_tree::MerkleTreeError;

        fn commit<M: p3_matrix::Matrix<F>>(
            &self,
            inputs: Vec<M>,
        ) -> (Self::Commitment, Self::ProverData<M>) {
            match self {
                Self::Cpu(m) => m.commit(inputs),
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => m.commit(inputs),
            }
        }

        fn open_batch<M: p3_matrix::Matrix<F>>(
            &self,
            index: usize,
            prover_data: &Self::ProverData<M>,
        ) -> p3_commit::BatchOpening<F, Self> {
            match self {
                Self::Cpu(m) => {
                    let o = m.open_batch(index, prover_data);
                    p3_commit::BatchOpening::new(o.opened_values, o.opening_proof)
                }
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => {
                    let o = m.open_batch(index, prover_data);
                    p3_commit::BatchOpening::new(o.opened_values, o.opening_proof)
                }
            }
        }

        fn get_matrices<'a, M: p3_matrix::Matrix<F>>(
            &self,
            prover_data: &'a Self::ProverData<M>,
        ) -> Vec<&'a M> {
            match self {
                Self::Cpu(m) => m.get_matrices(prover_data),
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => m.get_matrices(prover_data),
            }
        }

        fn verify_batch(
            &self,
            commit: &Self::Commitment,
            dimensions: &[p3_matrix::Dimensions],
            index: usize,
            batch_opening: p3_commit::BatchOpeningRef<'_, F, Self>,
        ) -> Result<(), Self::Error> {
            match self {
                Self::Cpu(m) => {
                    let o = p3_commit::BatchOpeningRef::<'_, F, CpuMmcs>::new(
                        batch_opening.opened_values,
                        batch_opening.opening_proof,
                    );
                    m.verify_batch(commit, dimensions, index, o)
                }
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => {
                    let o = p3_commit::BatchOpeningRef::<
                        '_,
                        F,
                        crate::pcs::merkle_cuda::CudaMerkleTreeMmcs,
                    >::new(
                        batch_opening.opened_values, batch_opening.opening_proof
                    );
                    m.verify_batch(commit, dimensions, index, o)
                }
            }
        }

        fn verify_multi_batch<R: AsRef<[F]> + PartialEq>(
            &self,
            commit: &Self::Commitment,
            dimensions: &[p3_matrix::Dimensions],
            indices: &[usize],
            opened_values: &[Vec<R>],
            proof: &Self::MultiProof,
        ) -> Result<(), Self::Error> {
            match self {
                Self::Cpu(m) => {
                    m.verify_multi_batch(commit, dimensions, indices, opened_values, proof)
                }
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => {
                    m.verify_multi_batch(commit, dimensions, indices, opened_values, proof)
                }
            }
        }

        fn open_multi_batch<M: p3_matrix::Matrix<F>>(
            &self,
            indices: &[usize],
            prover_data: &Self::ProverData<M>,
        ) -> (Vec<Vec<Vec<F>>>, Self::MultiProof) {
            match self {
                Self::Cpu(m) => m.open_multi_batch(indices, prover_data),
                #[cfg(feature = "cuda")]
                Self::Cuda(m) => m.open_multi_batch(indices, prover_data),
            }
        }
    }
}

#[cfg(not(feature = "cuda"))]
type MyMmcs = CpuMmcs;
#[cfg(feature = "cuda")]
type MyMmcs = backend::MmcsBackend;
#[cfg(not(feature = "cuda"))]
type MyDft = CpuDft;
#[cfg(feature = "cuda")]
type MyDft = backend::DftBackend;
type MyPcs = WhirProver<EF, F, MyDft, MyMmcs, MyChallenger, MyLayout>;

pub type Commitment = <MyPcs as MultilinearPcs<EF, MyChallenger>>::Commitment;
pub type ProverData = <MyPcs as MultilinearPcs<EF, MyChallenger>>::ProverData;
pub type Proof = <MyPcs as MultilinearPcs<EF, MyChallenger>>::Proof;
pub use p3_sumcheck::OpeningProtocol;

/// A WHIR PCS over Goldilocks configured for a single `2^num_variables` MLE.
pub struct Whir {
    pcs: MyPcs,
    perm: Perm,
    folding_factor: FoldingFactor,
    security_level: usize,
    pow_bits: usize,
    num_variables: usize,
    /// (commits, total seconds) spent inside `commit`, for performance telemetry.
    commit_stats: std::cell::Cell<(u64, f64)>,
    open_stats: std::cell::Cell<(u64, f64)>,
    verify_stats: std::cell::Cell<(u64, f64)>,
}

fn read_u64_le<R: std::io::Read>(reader: &mut R) -> std::io::Result<u64> {
    let mut buf = [0u8; 8];
    reader.read_exact(&mut buf)?;
    Ok(u64::from_le_bytes(buf))
}

impl Whir {
    /// Build a WHIR instance sized for a single `2^num_variables` multilinear
    /// polynomial. Security parameters are PoC-grade (90-bit, default PoW); the
    /// proof stays small enough that a `2^10` commitment runs in a couple seconds.
    pub fn new(num_variables: usize) -> Self {
        Self::with_params(num_variables, 90, 32)
    }

    /// Fast, low-security instance for tests and local iteration. Do not use for
    /// anything that needs real soundness.
    pub fn new_testing(num_variables: usize) -> Self {
        Self::with_params(num_variables, 32, 10)
    }

    pub fn with_params(num_variables: usize, security_level: usize, pow_bits: usize) -> Self {
        let folding_factor = FoldingFactor::Constant(5);
        let (num_rounds, _) = folding_factor
            .compute_number_of_rounds(num_variables)
            .expect("valid folding schedule");
        let mut round_log_inv_rates = Vec::with_capacity(num_rounds);
        let mut rate = 1;
        for round in 0..num_rounds {
            rate += folding_factor.at_round(round) - 1;
            round_log_inv_rates.push(rate);
        }
        let params = ProtocolParameters {
            security_level,
            pow_bits,
            folding_factor: folding_factor.clone(),
            soundness_type: SecurityAssumption::CapacityBound,
            starting_log_inv_rate: 1,
            round_log_inv_rates,
        };

        let perm = Perm::new_from_rng_128(&mut SmallRng::seed_from_u64(1));
        #[cfg(not(feature = "cuda"))]
        let mmcs = MyMmcs::new(
            MerkleHash::new(perm.clone()),
            MerkleCompress::new(perm.clone()),
            0,
        );
        #[cfg(feature = "cuda")]
        let mmcs = {
            let hash = MerkleHash::new(perm.clone());
            let compress = MerkleCompress::new(perm.clone());
            if backend::use_cuda_mmcs() {
                MyMmcs::Cuda(crate::pcs::merkle_cuda::CudaMerkleTreeMmcs::new(
                    hash, compress, 0,
                ))
            } else {
                MyMmcs::Cpu(CpuMmcs::new(hash, compress, 0))
            }
        };
        let config = WhirConfig::<EF, F, MyChallenger>::new(num_variables, params).unwrap();
        #[cfg(not(feature = "cuda"))]
        let dft = MyDft::new(1 << config.max_fft_size());
        #[cfg(feature = "cuda")]
        let dft = {
            if backend::use_cuda_dft() {
                MyDft::Cuda(crate::pcs::dft_cuda::CudaDft::new())
            } else {
                MyDft::Cpu(CpuDft::new(1 << config.max_fft_size()))
            }
        };
        let pcs = MyPcs::new(config, dft, mmcs);

        Whir {
            pcs,
            perm,
            folding_factor,
            security_level,
            pow_bits,
            num_variables,
            commit_stats: std::cell::Cell::new((0, 0.0)),
            open_stats: std::cell::Cell::new((0, 0.0)),
            verify_stats: std::cell::Cell::new((0, 0.0)),
        }
    }

    /// Number of `commit` calls and total wall-clock seconds spent inside them.
    pub fn commit_stats(&self) -> (u64, f64) {
        self.commit_stats.get()
    }
    pub fn open_stats(&self) -> (u64, f64) {
        self.open_stats.get()
    }
    pub fn verify_stats(&self) -> (u64, f64) {
        self.verify_stats.get()
    }

    fn fresh_challenger(&self) -> MyChallenger {
        let mut challenger = MyChallenger::new(self.perm.clone());
        let mut domain_separator = DomainSeparator::new(vec![]);
        self.pcs.add_domain_separator::<8>(&mut domain_separator);
        domain_separator.observe_domain_separator(&mut challenger);
        challenger
    }

    /// Commit to a flat MLE. Returns the commitment, prover data, and the public
    /// opening protocol (single table, single column, one point) used for open/verify.
    pub fn security_level(&self) -> usize {
        self.security_level
    }

    pub fn pow_bits(&self) -> usize {
        self.pow_bits
    }

    pub fn num_variables(&self) -> usize {
        self.num_variables
    }

    /// Reconstruct the public opening protocol for `num_tables` tables of arity
    /// `arity`, each opened at column 0 with a caller-supplied point. This is the
    /// exact protocol built by `commit` (num_tables == 1) and `commit_batch`.
    pub fn opening_protocol(&self, arity: usize, num_tables: usize) -> OpeningProtocol {
        let folding = self.folding_factor.at_round(0);
        let point_schedule: PointSchedule =
            std::iter::once(OpeningBatch::new(vec![0], Vec::new())).collect();
        let specs: Vec<TableSpec> = (0..num_tables)
            .map(|_| TableSpec::new(TableShape::new(arity, 1), point_schedule.clone()))
            .collect();
        OpeningProtocol::new(specs).pad_to_min_num_variables(folding)
    }

    /// Minimum proof-of-work bits required to reach `security_level` for a
    /// commitment of `2^num_variables` evaluations (folding factor 5, capacity
    /// bound). Models should adapt per group: pass this (or a larger) value as
    /// the group's `pow_bits`, so a large tensor (e.g. a 2^28 lm_head) gets a
    /// higher PoW budget while small groups stay cheap.
    pub fn required_pow_bits(num_variables: usize, security_level: usize) -> usize {
        let folding_factor = FoldingFactor::Constant(5);
        let (num_rounds, _) = folding_factor
            .compute_number_of_rounds(num_variables)
            .expect("valid folding schedule");
        let mut round_log_inv_rates = Vec::with_capacity(num_rounds);
        let mut rate = 1;
        for round in 0..num_rounds {
            rate += folding_factor.at_round(round) - 1;
            round_log_inv_rates.push(rate);
        }
        let params = ProtocolParameters {
            security_level,
            pow_bits: 0,
            folding_factor: folding_factor.clone(),
            soundness_type: SecurityAssumption::CapacityBound,
            starting_log_inv_rate: 1,
            round_log_inv_rates,
        };
        match WhirConfig::<EF, F, MyChallenger>::new(num_variables, params) {
            Ok(config) => config.max_pow_bits(),
            Err(WhirConfigError::PowBitsExceedBudget { required, .. }) => required,
            Err(e) => panic!("unexpected WhirConfig error: {e:?}"),
        }
    }

    pub fn commit(&self, evals: &[Goldilocks]) -> (Commitment, ProverData, OpeningProtocol) {
        let t0 = std::time::Instant::now();
        let num_vars = evals.len().trailing_zeros() as usize;
        assert_eq!(
            evals.len(),
            1 << num_vars,
            "MLE length must be a power of two"
        );

        // One polynomial (one row) whose `2^num_vars` evaluations form the row.
        let table = Table::new(RowMajorMatrix::new(evals.to_vec(), 1 << num_vars));
        let folding = self.folding_factor.at_round(0);
        let witness = MyLayout::new_witness(vec![table], folding);

        let point_schedule: PointSchedule =
            std::iter::once(OpeningBatch::new(vec![0], Vec::new())).collect();
        let protocol = OpeningProtocol::new(vec![TableSpec::new(
            TableShape::new(num_vars, 1),
            point_schedule,
        )])
        .pad_to_min_num_variables(folding);

        let (commitment, prover_data) = <MyPcs as MultilinearPcs<EF, MyChallenger>>::commit(
            &self.pcs,
            witness,
            &mut self.fresh_challenger(),
        );
        let (n, secs) = self.commit_stats.get();
        self.commit_stats
            .set((n + 1, secs + t0.elapsed().as_secs_f64()));
        (commitment, prover_data, protocol)
    }

    /// Open the committed MLE at `point` (base-field coordinates) and return the
    /// opening proof together with the claimed evaluation (in the extension field).
    /// Commit to multiple flat MLEs of the same size in a single WHIR witness.
    /// This amortizes the per-commit launch/transfer overhead, which is the
    /// dominant cost on the GPU path for many small commitments.
    pub fn commit_batch(
        &self,
        evals_batch: &[&[Goldilocks]],
    ) -> (Commitment, ProverData, OpeningProtocol, Whir) {
        let t0 = std::time::Instant::now();
        assert!(!evals_batch.is_empty(), "batch must not be empty");
        let arity = evals_batch[0].len().trailing_zeros() as usize;
        for e in evals_batch {
            assert_eq!(
                e.len(),
                1 << arity,
                "all MLEs in a batch must have the same size"
            );
        }
        let total_slots = evals_batch.len() * (1usize << arity);
        let total_num_vars = total_slots.next_power_of_two().trailing_zeros() as usize;

        let whir = Whir::with_params(total_num_vars, self.security_level, self.pow_bits);
        let tables: Vec<Table<F>> = evals_batch
            .iter()
            .map(|e| Table::new(RowMajorMatrix::new(e.to_vec(), 1 << arity)))
            .collect();
        let folding = whir.folding_factor.at_round(0);
        let witness = MyLayout::new_witness(tables, folding);

        let point_schedule: PointSchedule =
            std::iter::once(OpeningBatch::new(vec![0], Vec::new())).collect();
        let specs: Vec<TableSpec> = (0..evals_batch.len())
            .map(|_| TableSpec::new(TableShape::new(arity, 1), point_schedule.clone()))
            .collect();
        let protocol = OpeningProtocol::new(specs).pad_to_min_num_variables(folding);

        let (commitment, prover_data) = <MyPcs as MultilinearPcs<EF, MyChallenger>>::commit(
            &whir.pcs,
            witness,
            &mut whir.fresh_challenger(),
        );
        let (n, secs) = self.commit_stats.get();
        self.commit_stats.set((
            n + evals_batch.len() as u64,
            secs + t0.elapsed().as_secs_f64(),
        ));
        (commitment, prover_data, protocol, whir)
    }

    /// Reconstruct the public opening protocol for a committed same-arity table group.
    pub fn batch_opening_protocol(&self, num_tables: usize, arity: usize) -> OpeningProtocol {
        let folding = self.folding_factor.at_round(0);
        let point_schedule: PointSchedule =
            std::iter::once(OpeningBatch::new(vec![0], Vec::new())).collect();
        let specs = (0..num_tables)
            .map(|_| TableSpec::new(TableShape::new(arity, 1), point_schedule.clone()))
            .collect();
        OpeningProtocol::new(specs).pad_to_min_num_variables(folding)
    }

    /// Serialize the reusable Merkle tree; reconstruct layout state from source tables on load.
    pub fn serialize_batch_prover_data(
        prover_data: ProverData,
    ) -> Result<Vec<u8>, Box<dyn std::error::Error>> {
        let mut encoded = Vec::new();
        Self::serialize_batch_prover_data_into(prover_data, &mut encoded)?;
        Ok(encoded)
    }

    /// Stream the Merkle tree to persistent storage without cloning it into a second large buffer.
    pub fn serialize_batch_prover_data_into<W: std::io::Write>(
        prover_data: ProverData,
        writer: &mut W,
    ) -> Result<(), Box<dyn std::error::Error>> {
        let (_, merkle_data) = prover_data.into_parts();
        let leaves = merkle_data.leaves();
        writer.write_all(&(leaves.len() as u64).to_le_bytes())?;
        for leaf in leaves {
            writer.write_all(&(leaf.width as u64).to_le_bytes())?;
            writer.write_all(&(leaf.values.len() as u64).to_le_bytes())?;
            let byte_len = leaf.values.len() * std::mem::size_of::<F>();
            let bytes =
                unsafe { std::slice::from_raw_parts(leaf.values.as_ptr() as *const u8, byte_len) };
            writer.write_all(bytes)?;
        }
        let bytes = merkle_data.write_digest_layers();
        writer.write_all(&bytes)?;
        Ok(())
    }

    /// Restore prover data from an encoded Merkle tree without rebuilding the commitment.
    pub fn restore_batch_prover_data(
        &self,
        evals_batch: &[&[Goldilocks]],
        encoded: &[u8],
    ) -> Result<ProverData, Box<dyn std::error::Error>> {
        self.restore_batch_prover_data_from(evals_batch, &mut std::io::Cursor::new(encoded))
    }

    /// Stream and restore prover data from a cache file, rebuilding only layout state.
    pub fn restore_batch_prover_data_from<R: std::io::Read>(
        &self,
        evals_batch: &[&[Goldilocks]],
        reader: &mut R,
    ) -> Result<ProverData, Box<dyn std::error::Error>> {
        assert!(!evals_batch.is_empty());
        let arity = evals_batch[0].len().trailing_zeros() as usize;
        assert!(evals_batch
            .iter()
            .all(|values| values.len() == 1usize << arity));
        let num_leaves = read_u64_le(reader)? as usize;
        let mut leaves = Vec::with_capacity(num_leaves);
        for _ in 0..num_leaves {
            let width = read_u64_le(reader)? as usize;
            let len = read_u64_le(reader)? as usize;
            let mut values = vec![Goldilocks::new(0); len];
            let byte_len = len * std::mem::size_of::<F>();
            reader.read_exact(unsafe {
                std::slice::from_raw_parts_mut(values.as_mut_ptr() as *mut u8, byte_len)
            })?;
            leaves.push(RowMajorMatrix::new(values, width));
        }
        let mut bytes = Vec::new();
        reader.read_to_end(&mut bytes)?;
        let merkle_data =
            <MyMmcs as p3_commit::Mmcs<F>>::ProverData::<RowMajorMatrix<F>>::read_digest_layers(
                &bytes, leaves,
            );
        let tables = evals_batch
            .iter()
            .map(|values| Table::new(RowMajorMatrix::new(values.to_vec(), 1 << arity)))
            .collect();
        let witness = MyLayout::new_witness(tables, self.folding_factor.at_round(0));
        Ok(ProverData::from_parts(
            MyLayout::from_witness(witness),
            merkle_data,
        ))
    }

    pub fn open(
        &self,
        prover_data: ProverData,
        protocol: &OpeningProtocol,
        point: &[Goldilocks],
    ) -> (Proof, Goldilocks) {
        let t0 = std::time::Instant::now();
        let ef_point = to_ef_point(point);
        let proof = self.pcs.open_at(
            prover_data,
            protocol,
            std::slice::from_ref(&ef_point),
            &mut self.fresh_challenger(),
        );
        let opened = proof.evals[0].current()[0];
        let (n, secs) = self.open_stats.get();
        self.open_stats
            .set((n + 1, secs + t0.elapsed().as_secs_f64()));
        GLOBAL_OPEN_COUNT.fetch_add(1, std::sync::atomic::Ordering::Relaxed);
        (
            proof,
            opened
                .as_base()
                .expect("base-field MLE opens to a base element"),
        )
    }

    /// Verify the opening proof at `point` and return the opened evaluation.
    pub fn verify(
        &self,
        commitment: &Commitment,
        proof: &Proof,
        protocol: &OpeningProtocol,
        point: &[Goldilocks],
    ) -> Result<Goldilocks, <MyPcs as MultilinearPcs<EF, MyChallenger>>::Error> {
        let t0 = std::time::Instant::now();
        let ef_point = to_ef_point(point);
        let evals = self.pcs.verify_at(
            commitment,
            proof,
            protocol,
            std::slice::from_ref(&ef_point),
            &mut self.fresh_challenger(),
        )?;
        let (n, secs) = self.verify_stats.get();
        self.verify_stats
            .set((n + 1, secs + t0.elapsed().as_secs_f64()));
        Ok(evals[0].current()[0]
            .as_base()
            .expect("base-field MLE opens to a base element"))
    }
    /// Open the `table_index`-th MLE in a batch at `point`.
    pub fn open_batch(
        &self,
        prover_data: ProverData,
        protocol: &OpeningProtocol,
        table_index: usize,
        num_tables: usize,
        point: &[Goldilocks],
    ) -> (Proof, Goldilocks) {
        let t0 = std::time::Instant::now();
        let arity = point.len();
        let target = to_ef_point(point);
        let dummy = Point::new(vec![EF::from(Goldilocks::new(0)); arity]);
        let points: Vec<Point<EF>> = (0..num_tables)
            .map(|i| {
                if i == table_index {
                    target.clone()
                } else {
                    dummy.clone()
                }
            })
            .collect();
        let proof = self
            .pcs
            .open_at(prover_data, protocol, &points, &mut self.fresh_challenger());
        let opened = proof.evals[table_index].current()[0];
        let (n, secs) = self.open_stats.get();
        self.open_stats
            .set((n + 1, secs + t0.elapsed().as_secs_f64()));
        GLOBAL_OPEN_COUNT.fetch_add(1, std::sync::atomic::Ordering::Relaxed);
        (
            proof,
            opened
                .as_base()
                .expect("base-field MLE opens to a base element"),
        )
    }

    /// Verify the batch opening of the `table_index`-th MLE at `point`.
    pub fn verify_batch(
        &self,
        commitment: &Commitment,
        proof: &Proof,
        protocol: &OpeningProtocol,
        table_index: usize,
        num_tables: usize,
        point: &[Goldilocks],
    ) -> Result<Goldilocks, <MyPcs as MultilinearPcs<EF, MyChallenger>>::Error> {
        let arity = point.len();
        let target = to_ef_point(point);
        let dummy = Point::new(vec![EF::from(Goldilocks::new(0)); arity]);
        let points: Vec<Point<EF>> = (0..num_tables)
            .map(|i| {
                if i == table_index {
                    target.clone()
                } else {
                    dummy.clone()
                }
            })
            .collect();
        let evals = self.pcs.verify_at(
            commitment,
            proof,
            protocol,
            &points,
            &mut self.fresh_challenger(),
        )?;
        Ok(evals[table_index].current()[0]
            .as_base()
            .expect("base-field MLE opens to a base element"))
    }

    /// Open every MLE in a batch at the same `point` in a single FRI proof,
    /// amortizing the O(N log N) folding across all tables instead of paying
    /// it once per table. Returns `(proof, evals)` where `evals[i]` is the
    /// opening of table `i`.
    pub fn open_batch_multi(
        &self,
        prover_data: ProverData,
        protocol: &OpeningProtocol,
        num_tables: usize,
        point: &[Goldilocks],
    ) -> (Proof, Vec<Goldilocks>) {
        let t0 = std::time::Instant::now();
        let target = to_ef_point(point);
        let points: Vec<Point<EF>> = (0..num_tables).map(|_| target.clone()).collect();
        let proof = self
            .pcs
            .open_at(prover_data, protocol, &points, &mut self.fresh_challenger());
        let opened: Vec<Goldilocks> = proof
            .evals
            .iter()
            .map(|e| {
                e.current()[0]
                    .as_base()
                    .expect("base-field MLE opens to a base element")
            })
            .collect();
        let (n, secs) = self.open_stats.get();
        self.open_stats
            .set((n + 1, secs + t0.elapsed().as_secs_f64()));
        GLOBAL_OPEN_COUNT.fetch_add(1, std::sync::atomic::Ordering::Relaxed);
        (proof, opened)
    }

    /// Verify a batched opening of every MLE in the batch at the same `point`.
    pub fn verify_batch_multi(
        &self,
        commitment: &Commitment,
        proof: &Proof,
        protocol: &OpeningProtocol,
        num_tables: usize,
        point: &[Goldilocks],
    ) -> Result<Vec<Goldilocks>, <MyPcs as MultilinearPcs<EF, MyChallenger>>::Error> {
        let target = to_ef_point(point);
        let points: Vec<Point<EF>> = (0..num_tables).map(|_| target.clone()).collect();
        let evals = self.pcs.verify_at(
            commitment,
            proof,
            protocol,
            &points,
            &mut self.fresh_challenger(),
        )?;
        Ok(evals
            .iter()
            .map(|e| {
                e.current()[0]
                    .as_base()
                    .expect("base-field MLE opens to a base element")
            })
            .collect())
    }
}

/// Embed base-field coordinates into the degree-2 extension field.
///
/// The crate's hand-rolled `mle` uses "coordinate 0 = LSB of the flattened
/// index", while Plonky3's `Poly`/`Point` use "coordinate 0 = MSB" (big-endian).
/// Reversing here reconciles the two orderings at the commitment boundary.
fn to_ef_point(point: &[Goldilocks]) -> Point<EF> {
    Point::new(point.iter().rev().map(|&c| EF::from(c)).collect())
}

impl serde::Serialize for Whir {
    fn serialize<S: serde::Serializer>(&self, serializer: S) -> Result<S::Ok, S::Error> {
        use serde::ser::SerializeTuple;
        let mut t = serializer.serialize_tuple(3)?;
        t.serialize_element(&self.num_variables)?;
        t.serialize_element(&self.security_level)?;
        t.serialize_element(&self.pow_bits)?;
        t.end()
    }
}

impl<'de> serde::Deserialize<'de> for Whir {
    fn deserialize<D: serde::Deserializer<'de>>(deserializer: D) -> Result<Self, D::Error> {
        let (num_variables, security_level, pow_bits) =
            <(usize, usize, usize)>::deserialize(deserializer)?;
        Ok(Whir::with_params(num_variables, security_level, pow_bits))
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::common::field::{Goldilocks, XorShift64};
    use crate::common::mle;

    #[test]
    fn whir_batch_open_matches_mle_eval() {
        let mut rng = XorShift64::new(0xbeef);
        let whir = Whir::new_testing(8);
        let n = 4usize;
        let arity = 8usize;
        let evals: Vec<Vec<Goldilocks>> = (0..n)
            .map(|_| (0..(1usize << arity)).map(|_| rng.field()).collect())
            .collect();
        let refs: Vec<&[Goldilocks]> = evals.iter().map(|e| e.as_slice()).collect();
        let (commitment, prover_data, protocol, batch_whir) = whir.commit_batch(&refs);
        for i in 0..n {
            let point: Vec<Goldilocks> = (0..arity).map(|_| rng.field()).collect();
            let (proof, opened) =
                batch_whir.open_batch(prover_data.clone(), &protocol, i, n, &point);
            let verified = batch_whir
                .verify_batch(&commitment, &proof, &protocol, i, n, &point)
                .unwrap();
            assert_eq!(opened, verified);
            assert_eq!(verified, mle::eval(&evals[i], &point));
        }
    }

    #[test]
    fn whir_prescribed_open_matches_mle_eval() {
        let mut rng = XorShift64::new(0x5eed);
        let d = 6;
        let evals: Vec<Goldilocks> = (0..(1 << d)).map(|_| rng.field()).collect();
        // Fast instance on purpose. `Whir::new` is the production one (90-bit
        // security, `pow_bits = 32`), and the prover grinds ~2^32 transcript
        // hashes per opening for that PoW budget — minutes per test, which is
        // what used to make `cargo test -p zkie-core` look hung. Nothing here
        // exercises PoW or the security level: the test asserts that the
        // prescribed-point open/verify roundtrip returns the MLE evaluation.
        // The production parameters themselves are covered by
        // `new_and_new_testing_expose_their_parameters` below.
        let whir = Whir::new_testing(d);

        let point: Vec<Goldilocks> = (0..d).map(|_| rng.field()).collect();
        let (commitment, prover_data, protocol) = whir.commit(&evals);
        let (proof, opened) = whir.open(prover_data, &protocol, &point);
        let verified = whir.verify(&commitment, &proof, &protocol, &point).unwrap();

        assert_eq!(opened, verified);
        assert_eq!(verified, mle::eval(&evals, &point));
    }

    /// The two constructors differ only in parameters; assert the values here
    /// instead of paying for a 2^32-hash grind in every other test.
    #[test]
    fn new_and_new_testing_expose_their_parameters() {
        let production = Whir::new(8);
        assert_eq!(production.security_level(), 90);
        assert_eq!(production.pow_bits(), 32);
        assert_eq!(production.num_variables(), 8);

        let testing = Whir::new_testing(8);
        assert_eq!(testing.security_level(), 32);
        assert_eq!(testing.pow_bits(), 10);
    }

    #[test]
    fn commit_batch_inherits_security_parameters() {
        let mut rng = XorShift64::new(0xbaa7);
        let whir = Whir::with_params(5, 64, 7);
        let tables: Vec<Vec<Goldilocks>> = (0..3)
            .map(|_| (0..32).map(|_| rng.field()).collect())
            .collect();
        let refs: Vec<&[Goldilocks]> = tables.iter().map(Vec::as_slice).collect();

        let (_, _, _, batch_whir) = whir.commit_batch(&refs);

        assert_eq!(batch_whir.security_level, 64);
        assert_eq!(batch_whir.pow_bits, 7);
    }

    #[test]
    fn committed_batch_tree_survives_serialization_roundtrip() {
        let mut rng = XorShift64::new(0xbaa8);
        let arity = 5usize;
        let num_tables = 3usize;
        let whir = Whir::new_testing(arity);
        let tables: Vec<Vec<Goldilocks>> = (0..num_tables)
            .map(|_| (0..(1usize << arity)).map(|_| rng.field()).collect())
            .collect();
        let refs: Vec<&[Goldilocks]> = tables.iter().map(Vec::as_slice).collect();
        let (commitment, prover_data, _protocol, batch_whir) = whir.commit_batch(&refs);
        let metadata = crate::pcs::cache::BatchCacheMetadata::new(
            String::from("test-model"),
            String::from("group-0"),
            (0..num_tables)
                .map(|i| format!("layer-{i}-weight"))
                .collect(),
            arity as u32,
            num_tables as u32,
            32,
            10,
            [7u8; 32],
        );
        let mut encoded = Vec::new();
        crate::pcs::cache::write_header(&mut encoded, &metadata, &commitment).unwrap();
        Whir::serialize_batch_prover_data_into(prover_data, &mut encoded).unwrap();
        let mut cursor = std::io::Cursor::new(encoded);
        let (loaded_metadata, commitment) = crate::pcs::cache::read_header(&mut cursor).unwrap();
        assert_eq!(loaded_metadata, metadata);
        let restored = batch_whir
            .restore_batch_prover_data_from(&refs, &mut cursor)
            .unwrap();
        let protocol = batch_whir.batch_opening_protocol(num_tables, arity);
        let point: Vec<Goldilocks> = (0..arity).map(|_| rng.field()).collect();
        let (proof, opened) = batch_whir.open_batch_multi(restored, &protocol, num_tables, &point);
        let verified = batch_whir
            .verify_batch_multi(&commitment, &proof, &protocol, num_tables, &point)
            .unwrap();
        assert_eq!(opened, verified);
        assert_eq!(verified.len(), num_tables);
    }
}
