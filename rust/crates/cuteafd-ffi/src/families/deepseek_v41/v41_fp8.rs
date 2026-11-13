//! Library-borrowing native V4.1 block FP8 launch handle.
//! Geometry (32768,8192) is grouped WO-A: eight independent [4096,1024] projections.
use crate::{CuteafdDeviceBuffer, NativeLibrary};
use anyhow::{ensure, Result};
use std::{ffi::c_void, ptr::NonNull};

#[repr(C)]
#[derive(Debug, Clone, Copy, Default)]
pub struct V41Fp8Info {
    pub abi_version: u32,
    pub capacity_rows: u32,
    pub input_dim: u32,
    pub output_dim: u32,
    pub scratch_bytes: u64,
    pub values_offset: u64,
    pub row_scales_offset: u64,
    pub mma_scales_offset: u64,
    pub packed_weight_scale_bytes: u64,
}
const _: [(); 56] = [(); std::mem::size_of::<V41Fp8Info>()];

#[repr(C)]
#[derive(Debug, Clone, Copy, Default)]
pub(super) struct OutputReductionInfo {
    pub abi_version: u32,
    pub capacity_rows: u32,
    pub expected_rows: u32,
    pub split_slices: u32,
    pub all_rows: u32,
}
const _: [(); 20] = [(); std::mem::size_of::<OutputReductionInfo>()];

type InfoFn = unsafe extern "C" fn(i32, i32, i32, *mut V41Fp8Info) -> i32;
type InitFn = unsafe extern "C" fn(i32, i32, i32, *mut *mut c_void) -> i32;
type ScratchFn = unsafe extern "C" fn(*mut c_void, *mut c_void, u64, *mut f32, *mut c_void) -> i32;
type PackFn = unsafe extern "C" fn(*const u8, *mut u8, i32, i32, *mut c_void) -> i32;
type LaunchFn = unsafe extern "C" fn(
    *mut c_void,
    *const u16,
    *const f32,
    *const u8,
    *const u8,
    *mut c_void,
    u64,
    *const f32,
    *mut u16,
    i32,
    *mut c_void,
) -> i32;
pub struct V41Fp8Kernel<'a> {
    _library: &'a NativeLibrary,
    handle: NonNull<c_void>,
    info: V41Fp8Info,
    scratch: ScratchFn,
    pack: PackFn,
    launch: LaunchFn,
}
impl NativeLibrary {
    pub(super) fn v41_output_reduction_info(&self, capacity: u32, k: u32, n: u32)
        -> Result<OutputReductionInfo> {
        type ReductionFn = unsafe extern "C" fn(i32, i32, i32, *mut OutputReductionInfo) -> i32;
        let mut info = OutputReductionInfo::default();
        // SAFETY: the loaded library owns the symbol; out is a writable ABI value.
        let status = unsafe {
            let function: ReductionFn = *self.lib.get(b"cuteafd_v41_fp8_matrix_reduction_info")?;
            function(i32::try_from(capacity)?, i32::try_from(k)?, i32::try_from(n)?, &mut info)
        };
        ensure!(status == 0 && info.abi_version == 1 && info.capacity_rows == capacity
            && info.all_rows <= 1, "unsupported native output reduction ABI/recipe");
        Ok(info)
    }
    pub fn v41_fp8_info(&self, capacity: u32) -> Result<V41Fp8Info> {
        self.v41_fp8_matrix_info(capacity, 6144, 25600)
    }
    pub fn v41_fp8_matrix_info(
        &self,
        capacity: u32,
        input_dim: u32,
        output_dim: u32,
    ) -> Result<V41Fp8Info> {
        ensure!(
            matches!(
                (input_dim, output_dim),
                (6144, 25600)
                    | (5120, 2304)
                    | (2304, 5120)
                    | (5120, 1152)
                    | (1152, 5120)
                    | (15360, 5120)
                    | (5120, 1280)
                    | (1280, 32768)
                    | (1280, 16384)
                    | (1280, 4096)
                    | (5120, 512)
                    | (8192, 5120)
                    | (8192, 2560)
                    | (32768, 8192)
            ),
            "unsupported native FP8 matrix"
        );
        let capacity = i32::try_from(capacity)?;
        let function: InfoFn = unsafe { *self.lib.get(b"cuteafd_v41_fp8_matrix_info")? };
        let mut info = V41Fp8Info::default();
        let status = unsafe { function(capacity, input_dim as i32, output_dim as i32, &mut info) };
        ensure!(
            status == 0,
            "native V4.1 FP8 info failed with CUDA status {status}"
        );
        // Packed weight scales: one UE8M0 per 32 inputs of every output row in
        // the SM120 MMA layout, or the checkpoint's own [N/32, K/32] grid
        // (plain) where the export's kernels read it directly (SM89).
        let per_group = u64::from(input_dim) * u64::from(output_dim) / groups(input_dim, output_dim);
        ensure!(
            info.abi_version == 1
                && info.capacity_rows == capacity as u32
                && info.input_dim == input_dim
                && info.output_dim == output_dim
                && (info.packed_weight_scale_bytes == per_group / 32
                    || info.packed_weight_scale_bytes == per_group / 1024),
            "unsupported native V4.1 FP8 geometry/ABI"
        );
        ensure!(
            info.values_offset < info.scratch_bytes
                && info.row_scales_offset < info.scratch_bytes
                && info.mma_scales_offset < info.scratch_bytes,
            "invalid native FP8 scratch offsets"
        );
        Ok(info)
    }
    pub fn v41_fp8_kernel(&self, capacity: u32) -> Result<V41Fp8Kernel<'_>> {
        self.v41_fp8_matrix_kernel(capacity, 6144, 25600)
    }
    pub fn v41_fp8_matrix_kernel(
        &self,
        capacity: u32,
        input_dim: u32,
        output_dim: u32,
    ) -> Result<V41Fp8Kernel<'_>> {
        let info = self.v41_fp8_matrix_info(capacity, input_dim, output_dim)?;
        unsafe {
            let initialize: InitFn = *self.lib.get(b"cuteafd_v41_fp8_matrix_initialize")?;
            let scratch = *self.lib.get(b"cuteafd_v41_fp8_initialize_scratch")?;
            let pack = *self.lib.get(b"cuteafd_v41_fp8_matrix_pack_scales")?;
            let launch = *self.lib.get(b"cuteafd_v41_fp8_launch_rope")?;
            let mut handle = std::ptr::null_mut();
            let status = initialize(
                i32::try_from(capacity)?,
                input_dim as i32,
                output_dim as i32,
                &mut handle,
            );
            ensure!(
                status == 0,
                "native V4.1 FP8 initialization failed with CUDA status {status}"
            );
            let handle = NonNull::new(handle)
                .ok_or_else(|| anyhow::anyhow!("native FP8 returned null handle"))?;
            Ok(V41Fp8Kernel {
                _library: self,
                handle,
                info,
                scratch,
                pack,
                launch,
            })
        }
    }
}
fn require(buffer: CuteafdDeviceBuffer, bytes: usize) -> Result<()> {
    ensure!(
        !buffer.ptr.is_null() && buffer.bytes >= bytes,
        "native FP8 buffer is null or too small"
    );
    Ok(())
}
impl V41Fp8Kernel<'_> {
    pub fn info(&self) -> V41Fp8Info {
        self.info
    }
    /// # Safety
    /// Scratch and alpha are distinct current-device allocations that remain live
    /// until completion; initialize outside capture before executing/replaying.
    pub unsafe fn initialize_scratch(
        &self,
        scratch: CuteafdDeviceBuffer,
        alpha: CuteafdDeviceBuffer,
        stream: *mut c_void,
    ) -> Result<()> {
        require(scratch, usize::try_from(self.info.scratch_bytes)?)?;
        require(alpha, 4)?;
        let status = unsafe {
            (self.scratch)(
                self.handle.as_ptr(),
                scratch.ptr,
                scratch.bytes as u64,
                alpha.ptr.cast(),
                stream,
            )
        };
        ensure!(
            status == 0,
            "native FP8 scratch initialization failed with CUDA status {status}"
        );
        Ok(())
    }
    /// # Safety
    /// Source is native UE8M0 [output_dim/32,input_dim/32], or [8,32,128]
    /// for grouped WO-A. Destination is distinct current-device
    /// storage, with both allocations live and correctly ordered through completion.
    pub unsafe fn pack_scales(
        &self,
        source: CuteafdDeviceBuffer,
        destination: CuteafdDeviceBuffer,
        stream: *mut c_void,
    ) -> Result<()> {
        require(source, scale_grid_bytes(self.info.input_dim, self.info.output_dim)?)?;
        require(
            destination,
            usize::try_from(self.info.packed_weight_scale_bytes)?,
        )?;
        let status = unsafe {
            (self.pack)(
                source.ptr.cast(),
                destination.ptr.cast(),
                self.info.input_dim as i32,
                self.info.output_dim as i32,
                stream,
            )
        };
        ensure!(
            status == 0,
            "native FP8 scale packing failed with CUDA status {status}"
        );
        Ok(())
    }
    /// # Safety
    /// Source/output are BF16, weights native row-major FP8, scales packed by this
    /// kernel and alpha initialized to one. All buffers are distinct on the current
    /// device, correctly ordered on stream, and remain live through completion and
    /// any graph replay; scratch is exclusively owned by this in-flight wave.
    pub unsafe fn launch(
        &self,
        source: CuteafdDeviceBuffer,
        weight: CuteafdDeviceBuffer,
        scales: CuteafdDeviceBuffer,
        scratch: CuteafdDeviceBuffer,
        alpha: CuteafdDeviceBuffer,
        output: CuteafdDeviceBuffer,
        rows: u32,
        stream: *mut c_void,
    ) -> Result<()> {
        unsafe { self.launch_inner(source, None, weight, scales, scratch, alpha, output, rows, stream) }
    }
    /// Fuse V4.1 inverse RoPE with grouped input quantization.
    /// # Safety
    /// Same ownership as launch; frequencies are initialized FP32 [rows,32,2]
    /// on the current device and remain immutable through stream completion.
    pub unsafe fn launch_rope(
        &self,
        source: CuteafdDeviceBuffer,
        frequencies: CuteafdDeviceBuffer,
        weight: CuteafdDeviceBuffer,
        scales: CuteafdDeviceBuffer,
        scratch: CuteafdDeviceBuffer,
        alpha: CuteafdDeviceBuffer,
        output: CuteafdDeviceBuffer,
        rows: u32,
        stream: *mut c_void,
    ) -> Result<()> {
        unsafe { self.launch_inner(source, Some(frequencies), weight, scales, scratch, alpha, output, rows, stream) }
    }
    unsafe fn launch_inner(
        &self,
        source: CuteafdDeviceBuffer,
        frequencies: Option<CuteafdDeviceBuffer>,
        weight: CuteafdDeviceBuffer,
        scales: CuteafdDeviceBuffer,
        scratch: CuteafdDeviceBuffer,
        alpha: CuteafdDeviceBuffer,
        output: CuteafdDeviceBuffer,
        rows: u32,
        stream: *mut c_void,
    ) -> Result<()> {
        ensure!(
            rows > 0 && rows <= self.info.capacity_rows,
            "native FP8 rows exceed capacity"
        );
        if let Some(f) = frequencies {
            ensure!((self.info.input_dim,self.info.output_dim)==(32768,8192), "inverse RoPE requires grouped WO-A");
            require(f, rows as usize * 256)?;
        }
        require(source, rows as usize * self.info.input_dim as usize * 2)?;
        require(weight, weight_bytes(self.info.input_dim, self.info.output_dim)?)?;
        require(
            scales,
            usize::try_from(self.info.packed_weight_scale_bytes)?,
        )?;
        require(scratch, usize::try_from(self.info.scratch_bytes)?)?;
        require(alpha, 4)?;
        require(output, rows as usize * self.info.output_dim as usize * 2)?;
        let status = unsafe {
            (self.launch)(
                self.handle.as_ptr(),
                source.ptr.cast(),
                frequencies.map_or(std::ptr::null(), |f| f.ptr.cast()),
                weight.ptr.cast(),
                scales.ptr.cast(),
                scratch.ptr,
                scratch.bytes as u64,
                alpha.ptr.cast(),
                output.ptr.cast(),
                i32::try_from(rows)?,
                stream,
            )
        };
        self._library.status_to_result("native FP8 projection", status)?;
        Ok(())
    }
}

type SwiGluFn = unsafe extern "C" fn(*const u16, *const u16, *mut u16, i32, *mut c_void) -> i32;
pub struct V41SharedSwiGlu<'a> {
    _library: &'a NativeLibrary,
    launch: SwiGluFn,
    width: usize,
}
impl NativeLibrary {
    pub fn v41_shared_swiglu(&self) -> Result<V41SharedSwiGlu<'_>> {
        Ok(V41SharedSwiGlu {
            _library: self,
            launch: unsafe { *self.lib.get(b"cuteafd_v41_shared_swiglu")? },
            width: 2304,
        })
    }
    pub fn v41_shared_tp2_swiglu(&self) -> Result<V41SharedSwiGlu<'_>> {
        Ok(V41SharedSwiGlu { _library: self,
            launch: unsafe { *self.lib.get(b"cuteafd_v41_shared_tp2_swiglu")? }, width: 1152 })
    }
}
impl V41SharedSwiGlu<'_> {
    /// # Safety
    /// Inputs are initialized finite BF16 [rows,width] on the stream device.
    /// Output is distinct; all storage remains live and ordered through completion.
    pub unsafe fn launch(
        &self,
        gate: CuteafdDeviceBuffer,
        up: CuteafdDeviceBuffer,
        output: CuteafdDeviceBuffer,
        rows: u32,
        stream: *mut c_void,
    ) -> Result<()> {
        ensure!((1..=4096).contains(&rows), "invalid shared SwiGLU rows");
        for buffer in [gate, up, output] {
            require(buffer, rows as usize * self.width * 2)?;
        }
        let status = unsafe {
            (self.launch)(
                gate.ptr.cast(),
                up.ptr.cast(),
                output.ptr.cast(),
                rows as i32,
                stream,
            )
        };
        self._library.status_to_result("native shared SwiGLU CUDA status", status)?;
        Ok(())
    }
}

// The official WO-A projection is block diagonal over eight head groups.
fn groups(input: u32, output: u32) -> u64 {
    if (input, output) == (32768, 8192) { 8 } else { 1 }
}

/// FP8 weight bytes of a matrix: one E4M3 byte per element of each group.
fn weight_bytes(input: u32, output: u32) -> Result<usize> {
    Ok(usize::try_from(u64::from(input) * u64::from(output) / groups(input, output))?)
}

/// The checkpoint's UE8M0 weight-scale grid: one byte per 32 x 32 block. The
/// guards come from geometry, not from the packed size, whose ratio to the
/// grid depends on the architecture's layout (SM120 expands it, SM89 keeps it).
fn scale_grid_bytes(input: u32, output: u32) -> Result<usize> {
    Ok(weight_bytes(input, output)? / 1024)
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn weight_and_scale_guards_come_from_geometry() -> Result<()> {
        // Grouped WO-A, eight 4096 x 1024 blocks; the C side's src_bytes agrees.
        assert_eq!((weight_bytes(32768, 8192)?, scale_grid_bytes(32768, 8192)?), (33_554_432, 32_768));
        assert_eq!((weight_bytes(15360, 5120)?, scale_grid_bytes(15360, 5120)?), (78_643_200, 76_800));
        assert_eq!((weight_bytes(5120, 512)?, scale_grid_bytes(5120, 512)?), (2_621_440, 2_560));
        Ok(())
    }

    /// Every supported geometry at every exported projection capacity creates a
    /// kernel through this FFI from the library under test (SM120 packed or
    /// SM89 plain weight scales).
    #[test]
    #[ignore = "requires CUTEAFD_NATIVE_LIB with the V4.1 FP8 bundle and a GPU"]
    fn cuda_v41_fp8_matrices_create_at_every_exported_capacity() -> Result<()> {
        let library = unsafe { NativeLibrary::load(std::env::var("CUTEAFD_NATIVE_LIB")?)? };
        let geometries = [(6144, 25600), (5120, 2304), (2304, 5120), (5120, 1152), (1152, 5120), (15360, 5120),
            (5120, 1280), (1280, 32768), (1280, 16384), (1280, 4096), (5120, 512), (8192, 5120), (8192, 2560),
            (32768, 8192)];
        let capacities = [1, 16, cuteafd_core::V41_VERIFY_ROWS as u32, cuteafd_core::V41_DRAFT_LEGACY_ROWS as u32,
            256, 1024, 4096];
        for (input_dim, output_dim) in geometries {
            for capacity in capacities {
                let kernel = library.v41_fp8_matrix_kernel(capacity, input_dim, output_dim)?;
                let per_group = u64::from(input_dim) * u64::from(output_dim) / groups(input_dim, output_dim);
                let scales = kernel.info().packed_weight_scale_bytes;
                ensure!(scales == per_group / 32 || scales == per_group / 1024,
                    "{input_dim}x{output_dim} m{capacity}: {scales} packed scale bytes");
            }
        }
        Ok(())
    }
}

#[cfg(test)]
mod draft_failure_tests {
    use super::*;
    #[test]
    fn fp8_projection_native_failure_is_tagged() -> Result<()> {
        let library = crate::tests::draft_failure_library()?;
        unsafe extern "C" fn scratch(_: *mut c_void, _: *mut c_void, _: u64, _: *mut f32, _: *mut c_void) -> i32 { 0 }
        unsafe extern "C" fn pack(_: *const u8, _: *mut u8, _: i32, _: i32, _: *mut c_void) -> i32 { 0 }
        unsafe extern "C" fn launch(_: *mut c_void, _: *const u16, _: *const f32, _: *const u8,
            _: *const u8, _: *mut c_void, _: u64, _: *const f32, _: *mut u16, _: i32, _: *mut c_void) -> i32 { 98 }
        let kernel = V41Fp8Kernel { _library: &library, handle: NonNull::dangling(),
            info: V41Fp8Info { capacity_rows: 1, input_dim: 5120, output_dim: 512,
                packed_weight_scale_bytes: 81920, ..Default::default() }, scratch, pack, launch };
        let buffer = CuteafdDeviceBuffer { ptr: NonNull::<u16>::dangling().as_ptr().cast(),
            bytes: 4 << 20, device_id: 0, flags: 0 };
        // SAFETY: the injected native entry point never dereferences the synthetic buffers.
        crate::tests::assert_draft_native_failure(unsafe { kernel.launch(buffer, buffer, buffer,
            buffer, buffer, buffer, 1, std::ptr::null_mut()) });
        Ok(())
    }
}
