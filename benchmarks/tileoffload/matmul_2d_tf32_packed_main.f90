program matmul_2d_tf32_packed_tileoffload
  use bench_utils
  use tileoff_matmul_2d_tf32_packed_kernel
  use, intrinsic :: ieee_arithmetic, only: ieee_is_finite
  implicit none

  integer(8) :: n, m, k, packed_ld
  integer :: reps
  real, allocatable :: a(:, :), b(:, :), c(:, :), ap(:, :)
  real :: expected
  real :: diff, tol
  integer(8) :: i, j, p
  integer :: r, errors
  real(8) :: t0, t1, elapsed
  real(8) :: flops_per_rep

  call parse_i64_arg(1, 512_8, n)
  call parse_i64_arg(2, 512_8, m)
  call parse_i32_arg(3, 20, reps)

  if (n < 1 .or. m < 1 .or. reps < 1) stop 2

  k = n
  packed_ld = 16_8 * ((k + 15_8) / 16_8)

  allocate(a(n, k), b(k, m), c(n, m), ap(packed_ld,n))

  do p = 1, k
    do i = 1, n
      a(i, p) = 0.001 * real(mod(i - 1 + p - 1, 100_8))
    end do
  end do

  do j = 1, m
    do p = 1, k
      b(p, j) = 0.002 * real(mod(p - 1 + 2_8 * (j - 1), 100_8))
    end do
  end do

  c = 0.0

  call packed_prepare(a, b, c, ap)

  ! A is unchanged throughout this benchmark: pack once before timing.
  call packed_pack(a, ap)

  call packed_compute(ap, b, c)
  call packed_compute(ap, b, c)

  !$tileoff wait
  t0 = wall_time()

  do r = 1, reps
    call packed_compute(ap, b, c)
  end do

  !$tileoff wait
  t1 = wall_time()

  call packed_fetch(c)

  errors = 0

  do j = 1, m
    do i = 1, n
      expected = 0.0
      do p = 1, k
        expected = expected + a(i, p) * b(p, j)
      end do

      diff = abs(c(i, j) - expected)
      tol = 1.0e-2 + 1.0e-3 * abs(expected)

      if (.not. ieee_is_finite(c(i,j)) .or. diff > tol) then
        if (errors < 10) then
          write(*,*) "mismatch at ", i, j, " got ", c(i, j), &
                     " expected ", expected, " diff ", diff, " tol ", tol
        end if
        errors = errors + 1
      end if
    end do
  end do

  call packed_release(a, b, c, ap)

  elapsed = t1 - t0

  ! Rate counts matmul FLOPs only; repack mode includes packing in elapsed.
  ! Interpret final rate as GFLOP/s.
  flops_per_rep = 2.0d0 * real(n, 8) * real(m, 8) * real(k, 8)

  call print_result("tileoff_matmul_2d_tf32_packed", n, m, reps, elapsed, flops_per_rep, errors)

end program
