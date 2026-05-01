/*
 * SpinorML Ltd 🚀 AGPL-3.0 License - https://spinorml.com/license
 */

#[cfg(feature = "cuda")]
mod cuda {
    use dotenv::dotenv;
    use serial_test::serial;
    use teeny_compiler::compiler::{driver::cuda::compile_kernel, target::cuda::Target};
    use teeny_core::device::{Device, buffer::Buffer};
    use teeny_cuda::{errors::Result, testing};

    // Shape: (N=2, C=8, H=16, W=16) stored as a flat contiguous f32 buffer.
    const N: usize = 2 * 8 * 16 * 16; // 4096
    const BLOCK_SIZE: i32 = 128;

    fn load_fixture(rel: &str) -> Vec<f32> {
        let path = format!(
            "{}/tests/fixtures/silu_4d/{}",
            env!("CARGO_MANIFEST_DIR"),
            rel
        );
        let bytes = std::fs::read(&path).unwrap_or_else(|e| panic!("missing fixture {path}: {e}"));
        bytes
            .chunks_exact(4)
            .map(|b| f32::from_le_bytes([b[0], b[1], b[2], b[3]]))
            .collect()
    }

    #[test]
    #[serial]
    fn test_silu_4d_forward_cuda() -> Result<()> {
        dotenv().ok();
        let env = testing::setup_cuda_env()?;

        let x_host = load_fixture("x.bin");
        let expected = load_fixture("expected_forward.bin");
        let mut y_host = vec![0.0f32; N];

        let mut x_buf = env.device.buffer::<f32>(N)?;
        let y_buf = env.device.buffer::<f32>(N)?;
        x_buf.to_device(&x_host)?;

        let kernel = teeny_kernels::nn::activation::sigmoid::SiluForward::new(BLOCK_SIZE);
        let ptx = std::fs::read(compile_kernel(&kernel, &Target::new(env.capability), true)?)?;
        let program = testing::load_program_from_ptx::<
            teeny_kernels::nn::activation::sigmoid::SiluForward,
        >(&ptx)?;
        env.device.launch(
            &program,
            &testing::launch_config(N, BLOCK_SIZE),
            (
                x_buf.as_device_ptr() as *mut f32,
                y_buf.as_device_ptr() as *mut f32,
                N as i32,
            ),
        )?;
        y_buf.to_host(&mut y_host)?;

        for i in 0..N {
            assert!(
                (y_host[i] - expected[i]).abs() < 1e-5,
                "silu_4d_forward mismatch at {i}: got={} expected={}",
                y_host[i],
                expected[i],
            );
        }
        Ok(())
    }

    #[test]
    #[serial]
    fn test_silu_4d_backward_cuda() -> Result<()> {
        dotenv().ok();
        let env = testing::setup_cuda_env()?;

        let x_host = load_fixture("x.bin");
        let dy_host = load_fixture("dy.bin");
        let expected = load_fixture("expected_backward.bin");
        let mut dx_host = vec![0.0f32; N];

        let mut x_buf = env.device.buffer::<f32>(N)?;
        let mut dy_buf = env.device.buffer::<f32>(N)?;
        let dx_buf = env.device.buffer::<f32>(N)?;
        x_buf.to_device(&x_host)?;
        dy_buf.to_device(&dy_host)?;

        let kernel = teeny_kernels::nn::activation::sigmoid::SiluBackward::new(BLOCK_SIZE);
        let ptx = std::fs::read(compile_kernel(&kernel, &Target::new(env.capability), true)?)?;
        let program = testing::load_program_from_ptx::<
            teeny_kernels::nn::activation::sigmoid::SiluBackward,
        >(&ptx)?;
        env.device.launch(
            &program,
            &testing::launch_config(N, BLOCK_SIZE),
            (
                dy_buf.as_device_ptr() as *mut f32,
                x_buf.as_device_ptr() as *mut f32,
                dx_buf.as_device_ptr() as *mut f32,
                N as i32,
            ),
        )?;
        dx_buf.to_host(&mut dx_host)?;

        for i in 0..N {
            assert!(
                (dx_host[i] - expected[i]).abs() < 1e-5,
                "silu_4d_backward mismatch at {i}: got={} expected={}",
                dx_host[i],
                expected[i],
            );
        }
        Ok(())
    }
}
