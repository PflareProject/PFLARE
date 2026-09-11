module gmres_poly

   use petscmat
   use sorting, only: intersect_pre_sorted_indices_only, merge_pre_sorted
   use c_petsc_interfaces, only: mat_mult_powers_share_sparsity_kokkos
   use pflare_parameters, only: PFLAREINV_POWER, PFLAREINV_ARNOLDI, PFLAREINV_NEWTON, &
         PFLAREINV_NEWTON_NO_EXTRA, MF_VEC_DIAG, MF_VEC_RHS, MF_VEC_TEMP, &
         MF_VEC_TEMP_TWO, MF_VEC_TEMP_THREE, &
         PFLARE_TOL_ZERO, PFLARE_TOL_ARNOLDI, PFLARE_TOL_MATFREE_4EM11, &
         PFLARE_TOL_LUCKY, PFLARE_ONE, PFLARE_ZERO, PFLARE_MINUS_ONE, PFLARE_MATMULT_FILL, &
         PFLARE_REAL_KIND
   use matshell_data_type, only: mat_ctxtype
   use gmres_poly_apply, only: petsc_matvec_poly_mf, petsc_matvec_right_scale_poly_mf, &
         petsc_matvec_da_poly_mf, petsc_matvec_poly_transpose_mf
   use tsqr, only: finish_tsqr_parallel, start_tsqr, tsqr_buffers
   use gmres_poly_data_type, only: gmres_poly_data
   use petsc_helper, only: MatAXPYWrapper, destroy_matrix_reuse, &
         kokkos_debug, mat_duplicate_copy_plus_diag, generate_identity

#include "petsc/finclude/petscmat.h"
#include "finclude/pflare_blaslapack.h"

   implicit none

   ! Just define pi
   ! Kind-suffixed with the build's PetscReal kind: full double precision in double
   ! builds (previously truncated to single even there - the one intended
   ! double-numeric change) and no -Wconversion under single.
   PetscReal, parameter, private :: pi = 3.141592653589793_PFLARE_REAL_KIND
   type int_vec
      integer, dimension(:), pointer :: ptr
   end type int_vec
   type real_vec
      PetscReal, dimension(:), pointer :: ptr
   end type real_vec   

   public

   contains

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine setup_gmres_poly_data(global_rows, inverse_type, poly_order, &
                  poly_sparsity_order, subcomm, proc_stride, poly_data)   

      ! Setups the gmres poly data structure and does some size checking

      ! ~~~~~~
      PetscInt, intent(in)                              :: global_rows, proc_stride
      integer, intent(in)                               :: inverse_type, poly_order
      integer, intent(in)                               :: poly_sparsity_order
      logical, intent(in)                               :: subcomm
      type(gmres_poly_data), intent(inout)              :: poly_data
      ! ~~~~~~            

      ! For gmres polynomial calculation we can move the reductions onto a subcomm
      if (inverse_type == PFLAREINV_POWER .OR. &
          inverse_type == PFLAREINV_ARNOLDI .OR. &
          inverse_type == PFLAREINV_NEWTON .OR. &
          inverse_type == PFLAREINV_NEWTON_NO_EXTRA) then
         poly_data%buffers%subcomm = subcomm
      end if   
      poly_data%buffers%proc_stride = int(proc_stride)

      poly_data%inverse_type = inverse_type
      ! For matrices with size smaller than the subspace size (ie polynomial order + 1)
      ! we'll have (close to) an exact solver and only need to go up to the matrix size
      poly_data%gmres_poly_order = poly_order
      if (poly_data%gmres_poly_order + 1 > global_rows) then
         poly_data%gmres_poly_order = int(global_rows - 1)
      end if        

      ! If we've changed the polynomial order lets make sure we aren't trying to take 
      ! sparsity bigger than it
      poly_data%gmres_poly_sparsity_order = poly_sparsity_order
      if (poly_data%gmres_poly_sparsity_order > poly_data%gmres_poly_order) then
         poly_data%gmres_poly_sparsity_order = poly_data%gmres_poly_order
      end if      

      ! Now we know the order we can create our coefficient vector
      if (inverse_type == PFLAREINV_NEWTON .OR. inverse_type == PFLAREINV_NEWTON_NO_EXTRA) then
         ! Newton basis we have to store real and imag roots
         if (.NOT. associated(poly_data%coefficients)) allocate(poly_data%coefficients(poly_data%gmres_poly_order + 1, 2))
      else
         if (.NOT. associated(poly_data%coefficients)) allocate(poly_data%coefficients(poly_data%gmres_poly_order + 1, 1))
      end if

   end subroutine setup_gmres_poly_data

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine compute_mf_gmres_poly_num_matvecs(inverse_type, coefficients, matvecs)   

      ! Computes how many matvecs we need to apply our matrix-free gmres polynomial

      ! ~~~~~~
      integer, intent(in)                               :: inverse_type
      PetscReal, dimension(:, :), intent(in)                 :: coefficients
      integer, intent(out)                              :: matvecs

      integer :: i_loc
      logical :: zero_root
      ! ~~~~~~       
      
      ! What order is our polynomial
      matvecs = size(coefficients,1)

      ! We may have zero roots with newton that are skipped
      if (inverse_type == PFLAREINV_NEWTON) then
         do i_loc = 1, size(coefficients,1)
            zero_root = .FALSE.
            if (coefficients(i_loc,2) == 0d0) then
               ! The size of the zero check here has to match that in 
               ! petsc_matvec_gmres_newton_mf and petsc_matvec_gmres_newton_mf_residual
               if (abs(coefficients(i_loc,1)) < PFLARE_TOL_ZERO) zero_root = .TRUE.
            else
               if (coefficients(i_loc,1)**2 + &
                        coefficients(i_loc,2)**2 < PFLARE_TOL_ZERO) zero_root = .TRUE.
            end if

            if (zero_root) then
               matvecs = matvecs - 1
            end if
         end do

      ! For power or Arnoldi   
      else
         ! The size of the zero check is exactly 0d0, normally can only happen
         ! in an Arnoldi that terminates early
         do i_loc = 1, size(coefficients,1)
            if (abs(coefficients(i_loc,1)) == 0d0) then
               matvecs = matvecs - 1
            end if
         end do         
      end if      

   end subroutine compute_mf_gmres_poly_num_matvecs   

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine create_temp_space_box_muller(matrix, subspace_size, V_n)
      
      ! Creates some temporary space and computes box muller random numbers
      ! in the first column

      ! ~~~~~~
      type(tMat), intent(in)                                      :: matrix
      integer, intent(in)                                         :: subspace_size
      type(tVec), pointer, dimension(:)                           :: V_n

      ! Local variables
      MPIU_Comm :: MPI_COMM_MATRIX
      PetscInt :: local_rows, local_cols, global_rows, global_cols
      PetscInt :: global_row_start, global_row_end_plus_one, row_i, vecs_needed
      PetscCount :: vec_size
      PetscInt, allocatable, dimension(:) :: indices
      integer :: i_loc, seed_size, comm_size, comm_rank, errorcode
      PetscErrorCode :: ierr      
      integer, dimension(:), allocatable :: seed
      ! Kept PetscReal: the intrinsic random_number requires a real array. Its use
      ! in VecSetValuesCOO below is an identity conversion in all real builds.
      PetscReal, dimension(:, :), allocatable, target   :: random_data
      type(tVec) :: temp_vec
      PetscInt, parameter :: one=1, zero=0
      ! ~~~~~~    

      ! We might want to call the gmres poly creation on a sub communicator
      ! so let's get the comm attached to the matrix and make sure to use that 
      call PetscObjectGetComm(matrix, MPI_COMM_MATRIX, ierr)  
      ! Get the comm size 
      call MPI_Comm_size(MPI_COMM_MATRIX, comm_size, errorcode)     
      ! Get the comm rank
      call MPI_Comm_rank(MPI_COMM_MATRIX, comm_rank, errorcode)     
      ! Get the matrix sizes
      call MatGetSize(matrix, global_rows, global_cols, ierr)
      call MatGetLocalSize(matrix, local_rows, local_cols, ierr)     
      call MatGetOwnershipRange(matrix, global_row_start, global_row_end_plus_one, ierr)  

      ! ~~~~~~~~~~
      ! Create random vector - this happens on the cpu
      ! We could do most of the box-muller on the gpu, but currently the random numbers in petsc 
      ! are still generated on the host (and we don't have portable trig functions in petsc across the different
      ! gpu vec types), so that would cause more copies to/from the gpu     
      ! If that changes this should be rewritten so this all happens on the gpu  
      ! ~~~~~~~~~~      

      ! If you ever change this to use PetscRandomCreate and VecSetRandom in petsc
      ! make sure the seed is different than when random is used to evaluate 
      ! the auto truncation in AIR_MG_Setup

      call random_seed(size=seed_size)
      allocate(seed(seed_size))
      ! Ensure we seed the same so subsequent runs get the same random
      ! Seed different on each process so we don't have the same random numbers on each processor      
      do i_loc = 1, seed_size
         seed(i_loc) = comm_rank + 1 + i_loc
      end do   
      call random_seed(put=seed)    

      ! Gives random numbers between 0 <= u < 1  
      allocate(random_data(local_rows, 2))
      ! Random numbers returned in fortran don't include one so don't have to 
      ! remove 1 
      call random_number(random_data(:, 1:2))

      ! We want our random rhs to be a normal distribution with zero mean as that preserves
      ! white noise in the eigenspace (ie it is rotation invariant to unitary transforms)
      ! Do a box-muller to take two numbers with uniform distribution and produce a number
      ! that is normally distributed       
      random_data(:, 1) = sqrt(-2 * log(random_data(:, 1))) * cos(2 * pi * random_data(:, 2))
      deallocate(seed)

      ! ~~~~~~~~~~
      ! Create a single template vec, set the random values into it, then use
      ! VecDuplicateVecs to allocate all V_n vectors in one contiguous block.
      ! Contiguous allocation lets VecMAXPY use BLAS-2 operations.
      ! ~~~~~~~~~~
      call MatCreateVecs(matrix, temp_vec, PETSC_NULL_VEC, ierr)

      allocate(indices(local_rows))
      ! Set the random values into the template vector
      ! Data will be copied to the gpu when needed
      do row_i = 1, local_rows
         indices(row_i) = global_row_start + row_i-1
      end do
      ! PetscCount vs PetscInt??
      vec_size = local_rows
      call VecSetPreallocationCOO(temp_vec, vec_size, indices, ierr)
      deallocate(indices)
      call VecSetValuesCOO(temp_vec, random_data(:, 1), INSERT_VALUES, ierr)

      deallocate(random_data)
      vecs_needed = subspace_size + 1

      ! Allocate all subspace_size+1 vectors contiguously from the template
      call VecDuplicateVecs(temp_vec, vecs_needed, V_n, ierr)
      ! Copy random data from template into the first vector
      call VecCopy(temp_vec, V_n(1), ierr)
      call VecDestroy(temp_vec, ierr)

      ! ~~~~~~~~~~~~

   end subroutine create_temp_space_box_muller  
   
! -------------------------------------------------------------------------------------------------------------------------------

   subroutine ls_solve_arnoldi(beta, m, H_n, y)

      ! Do the least-squares solve used in an arnoldi

      ! ~~~~~~
      PetscReal, intent(in)                     :: beta
      integer, intent(in)                  :: m
      PetscReal, dimension(:,:), intent(in)     :: H_n
      PetscReal, dimension(:), intent(inout)    :: y

      ! Local variables
      ! BLAS/LAPACK integer arguments must be PetscBLASInt
      PetscBLASInt :: errorcode, lwork
      PetscBLASInt :: m_bl, n_bl, nrhs_bl, lda_bl, ldb_bl
      PetscReal, dimension(size(H_n,1), size(H_n,2)) :: H_n_copy
      PetscReal, dimension(m+1) :: g0
      PetscReal, dimension(:), allocatable :: work

      ! ~~~~~~

      ! This is the vector we will use as rhs in the least square solve
      g0 = 0d0
      g0(1) = beta

      ! Let's solve our least squares system
      allocate(work(1))
      lwork = -1

      ! Make a copy as we do a least-squares solve in place
      H_n_copy(1:m+1, 1:m) = H_n(1:m+1, 1:m)

      ! Kind-correct BLAS integer dimensions
      m_bl = m+1
      n_bl = m
      nrhs_bl = 1
      lda_bl = size(H_n_copy, 1)
      ldb_bl = size(g0)

      lwork = -1
      ! Overwrite y
      errorcode = 0
      call PFLAREgels('N', m_bl, n_bl, nrhs_bl, H_n_copy(1,1), lda_bl, g0, ldb_bl, work, lwork, errorcode)
      ! Workspace query returns optimal lwork in work(1); int() is exact for all
      ! plausible sizes < 2^24 even when work is single precision
      lwork = int(work(1))
      deallocate(work)
      allocate(work(lwork))
      call PFLAREgels('N', m_bl, n_bl, nrhs_bl, H_n_copy(1,1), lda_bl, g0, ldb_bl, work, lwork, errorcode)
      deallocate(work)

      if (errorcode /= 0) then
         print *, "LS solve failed"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if  

      ! Set to zero necessary as sometimes we terminate our arnoldi early
      y = 0
      y(1:m) = g0(1:m)

   end subroutine ls_solve_arnoldi   
   
! -------------------------------------------------------------------------------------------------------------------------------

   subroutine arnoldi(matrix, poly_order, lucky_tol, V_n, w_j, beta, H_n, m, C_n, y, user_rel_tol)

      ! Arnoldi to compute H_n and optionally C_n (although computing C_n 
      ! won't be stable at high order)

      ! ~~~~~~
      type(tMat), intent(in)                            :: matrix
      integer, intent(in)                               :: poly_order
      PetscReal, intent(in)                                  :: lucky_tol
      type(tVec), dimension(:), intent(in)              :: V_n
      type(tVec), intent(in)                            :: w_j
      PetscReal, intent(out)                                 :: beta
      PetscReal, dimension(:,:), intent(inout)               :: H_n
      PetscReal, dimension(:,:), optional, intent(inout)     :: C_n
      PetscReal, optional, intent(inout)                     :: user_rel_tol
      PetscReal, dimension(:), optional, intent(inout)       :: y
      integer, intent(out)                              :: m

      ! Local variables
      integer :: i_loc, subspace_size
      PetscErrorCode :: ierr
      PetscReal, dimension(poly_order+2) :: c_j, g0
      PetscReal, dimension(poly_order+1) :: neg_h
      logical :: compute_cn
      PetscReal :: rel_tol
      PetscInt :: m_petscint
      ! Kind-correct BLAS integer/real arguments for the dgemv call
      PetscBLASInt :: m_bl, n_bl, lda_bl, one_bl
      PetscReal :: blas_one, blas_zero

      ! ~~~~~~   
            
      compute_cn = .FALSE.
      if (present(C_n)) compute_cn = .TRUE.
      ! Only compute H_n until we hit a given relative residual tolerance if it is input by the user
      rel_tol = -1
      if (present(user_rel_tol)) rel_tol = user_rel_tol

      ! This is how many columns we have in K_m
      subspace_size = poly_order + 1   

      ! This is the hessenberg matrix
      H_n = 0d0
      ! This stores part of the polynomial coefficients             
      if (compute_cn) C_n = 0d0

      ! ~~~~~~~~~
      ! Now time for a GMRES
      ! ~~~~~~~~~

      ! Compute the norm of the initial residual
      call VecNorm(V_n(1), NORM_2, beta, ierr)
      ! Now normalise to create the first orthogonal vector in V_n(1)
      call VecNormalize(V_n(1), beta, ierr)

      ! The first entry in C_n - As V_n = K_n C_n
      ! the first orthogonalised vector in V_n is just r0/beta, 
      ! and we know r0 is the first vector in our krylov subspace
      if (compute_cn) C_n(1,1) = PFLARE_ONE/beta

      ! Now loop through and do the iterations up to the max order of the polynomial
      ! we want to build
      do m = 1, subspace_size

         m_petscint = m    

         ! Compute w_j = A v_j
         call MatMult(matrix, &
                  V_n(m), &
                  w_j, ierr)  

         ! Now compute the updated relationship between K_n and V_n
         if (compute_cn) then
            c_j = 0d0
            ! This is [0 c1..cn] for column m
            c_j(2:m + 1) = C_n(1:m, m)  
         end if
                  
         ! Compute all hessenberg entries H_n(1:m, m) = <w_j, V_n(i)> in one reduction
         ! neg_h is used as a contiguous temporary since H_n is an assumed-shape 2D array
         call VecMDot(w_j, m_petscint, V_n, neg_h, ierr)
         H_n(1:m, m) = neg_h(1:m)

         ! w_j = w_j - sum_i H_n(i,m) * V_n(i)  (all at once)
         neg_h(1:m) = -neg_h(1:m)
         call VecMAXPY(w_j, m_petscint, neg_h, V_n, ierr)

         ! This is doing -C_n * h_n
         if (compute_cn) then
            do i_loc = 1, m
               c_j(1:i_loc) = c_j(1:i_loc) - C_n(1:i_loc, i_loc) * H_n(i_loc, m)
            end do
         end if

         ! Now compute new hessenberg entry
         call VecNorm(w_j, NORM_2, H_n(m+1, m), ierr)

         ! GMRES lucky tolerance, we're fully converged
         if (H_n(m+1, m) < lucky_tol) then
            ! Don't forget to update the ls solution if you exit early
            if (rel_tol > 0) call ls_solve_arnoldi(beta, m, H_n, y)
            exit
         end if

         ! v_j+1 = w_j / h_j+1,j
         call VecAXPBY(V_n(m + 1), &
                  PFLARE_ONE/H_n(m+1, m), &
                  PFLARE_ZERO, &
                  w_j, ierr)           

         ! Now we've taken out the H_n(m+1, m) factor from above
         if (compute_cn) C_n(1:m+1, m + 1) = c_j(1:m+1)/H_n(m+1, m)

         ! ~~~~~~
         ! Compute the residual if the user requested only solving to a specific 
         ! relative residual - we don't need it otherwise
         ! The residual is just ||H_m y - e_1 beta||_2, so we have to solve that least squares problem to find 
         ! y and then just compute 
         ! ~~~~~~
         if (rel_tol > 0) then

            call ls_solve_arnoldi(beta, m, H_n, y)

            ! Compute H_n y
            m_bl = m+1
            n_bl = m
            lda_bl = size(H_n,1)
            one_bl = 1
            blas_one = 1d0
            blas_zero = 0d0
            call PFLAREgemv("N", m_bl, n_bl, &
                  blas_one, H_n, lda_bl, &
                  y, one_bl, &
                  blas_zero, g0(1), one_bl)

            ! Minus away e1 beta
            g0(1) = g0(1) - beta
            ! This is the relative residual
            user_rel_tol = norm2(g0(1:m))/beta
            !print *, m, "rel residual", user_rel_tol
            if (user_rel_tol < rel_tol) exit
         end if

      end do

      ! Fortran allocates loop variables one bigger if we get to the end of the loop
      if (m == subspace_size + 1) m = m - 1

   end subroutine arnoldi      

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine calculate_gmres_polynomial_coefficients_arnoldi(matrix, poly_order, coefficients, user_rel_tol)

      ! Computes a fixed order gmres polynomial for the matrix passed in
      ! and stores each of the polynomial coefficients in coefficients
      ! This computes the coefficients using the Arnoldi basis
      ! This won't be stable at high order, but is stable at higher order than
      ! using the power basis. The cost of this is many reductions in parallel
      ! There is a comms-avoiding one given in start_gmres_polynomial_coefficients_power 
      ! which is stable for low order

      ! ~~~~~~
      type(tMat), intent(in)                            :: matrix
      integer, intent(in)                               :: poly_order
      PetscReal, dimension(:), intent(out)                   :: coefficients
      PetscReal, optional, intent(inout)                     :: user_rel_tol

      ! Local variables
      PetscInt :: global_rows, global_cols, vecs_needed
      integer :: subspace_size, m
      integer :: errorcode
      PetscErrorCode :: ierr
      PetscReal, dimension(poly_order+2,poly_order+1) :: H_n
      PetscReal, dimension(poly_order+2,poly_order+2) :: C_n
      PetscReal, dimension(poly_order+1) :: y
      PetscReal :: beta
      type(tVec) :: w_j
      type(tVec), pointer, dimension(:) :: V_n
      PetscReal :: rel_tol
      ! Kind-correct BLAS integer/real arguments for the dgemv call
      PetscBLASInt :: m_bl, lda_bl, one_bl
      PetscReal :: blas_one, blas_zero

      ! ~~~~~~    

      ! This is how many columns we have in K_m
      subspace_size = poly_order + 1   
      ! Get the matrix sizes
      call MatGetSize(matrix, global_rows, global_cols, ierr)

      ! ~~~~~~~~~~~~~
      ! We're basically just writing a simple GMRES here with no restart, the reason we can't use the petsc one
      ! is we need access to the unrotated hessenberg matrix, and the orthogonalised vectors
      ! to compute the gmres polynomial
      ! See Nachtigal et al 1992 for details on how we generate the gmres polynomial 
      ! coefficients using the Arnoldi basis
      ! ~~~~~~~~~~~~~

      if (subspace_size > global_rows) then
         print *, "The input subspace size is greater than the matrix size"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if

      ! ~~~~~~~~~~
      ! Allocate space and create random numbers 
      ! The first vec has random numbers in it
      ! ~~~~~~~~~~ 
      call create_temp_space_box_muller(matrix, subspace_size, V_n)
      
      ! Create an extra vector for storage
      call VecDuplicate(V_n(1), w_j, ierr)         

      ! Do the Arnoldi and compute H_n and C_n
      ! We only compute H_n until we hit a relative residual of 1e-14 against the random rhs
      ! or we hit the given poly_order
      rel_tol = PFLARE_TOL_ARNOLDI
      if (present(user_rel_tol)) rel_tol = user_rel_tol
      call arnoldi(matrix, poly_order, PFLARE_TOL_LUCKY, V_n, w_j, beta, H_n, m, C_n, y, rel_tol)
      if (present(user_rel_tol)) user_rel_tol = rel_tol

      ! ~~~~~~~~~~~~~
      ! Compute the polynomial coefficients, this is C_n(1:m, 1:m) y
      ! ~~~~~~~~~~~~~
      ! Set to zero is necessary as m may be less than the subspace_size
      coefficients = 0
      m_bl = m
      lda_bl = size(C_n,1)
      one_bl = 1
      blas_one = 1d0
      blas_zero = 0d0
      call PFLAREgemv("N", m_bl, m_bl, &
               blas_one, C_n, lda_bl, &
               y, one_bl, &
               blas_zero, coefficients(1), one_bl)

      vecs_needed = subspace_size + 1
      call VecDestroyVecs(vecs_needed, V_n, ierr)
      call VecDestroy(w_j, ierr)

   end subroutine calculate_gmres_polynomial_coefficients_arnoldi   

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine start_gmres_polynomial_coefficients_power(matrix, poly_order, buffers, coefficients)
      
      ! Computes a fixed order gmres polynomial for the matrix passed in
      ! and stores each of the polynomial coefficients in coefficients
      ! This computes the polynomial coefficients in the power basis using 
      ! the power basis
      ! This allows us to do a 1-step method that is comms reducing
      ! only requiring a single reduction in parallel
      ! If in parallel this is non-blocking and you have to call
      ! finish_gmres_polynomial_coefficients_power outside this routine to finish

      ! ~~~~~~
      type(tMat), intent(in)                            :: matrix
      integer, intent(in)                               :: poly_order
      type(tsqr_buffers), intent(inout)                 :: buffers
      PetscReal, dimension(:), intent(inout)                 :: coefficients

      ! Local variables
      PetscInt :: global_rows, global_cols, local_rows, local_cols
      PetscInt :: global_row_start, global_row_end_plus_one, row_i, vecs_needed
      PetscInt, dimension(:), allocatable :: global_indices
      integer :: comm_size, subspace_size, comm_rank, i_loc
      integer :: errorcode
      PetscErrorCode :: ierr      
      MPIU_Comm :: MPI_COMM_MATRIX
      PetscReal, dimension(:, :), allocatable, target :: K_m_plus_1_data
      type(tVec), pointer, dimension(:) :: V_n
      ! ~~~~~~    

      ! This is how many columns we have in K_m
      subspace_size = poly_order + 1

      ! We might want to call the gmres poly creation on a sub communicator
      ! so let's get the comm attached to the matrix and make sure to use that 
      call PetscObjectGetComm(matrix, MPI_COMM_MATRIX, ierr) 
      ! Get the comm size 
      call MPI_Comm_size(MPI_COMM_MATRIX, comm_size, errorcode)     
      ! Get the comm rank
      call MPI_Comm_rank(MPI_COMM_MATRIX, comm_rank, errorcode)     
      ! Get the matrix sizes
      call MatGetSize(matrix, global_rows, global_cols, ierr)
      call MatGetLocalSize(matrix, local_rows, local_cols, ierr)

      if (subspace_size > global_rows) then
         print *, "The input subspace size must be smaller than the matrix size"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if

      ! ~~~~~~~~~
      ! GMRES(m) will minimise the residual over the subspace
      ! K_m = [ b, A b, A^2 b, ... A^(m-1) b]
      ! A normal GMRES algorithm will use m dot products (ie m reductions) and m matvecs to 
      ! compute an orthgonal basis of this subspace directly with an Arnoldi
      ! without needing to compute the power basis K_m directly. 
      ! Equivalently, we can compute the gmres polynomial coefficients, g, by 
      ! solving the least squares system
      ! min || b - A K_m g ||
      ! Rather than having to compute the QR factorisation of A K_m and 
      ! than also have to compute the norm of b, we note that
      ! A K_m = K_m+1(:,2:end)
      ! It takes m matvecs to compute K_m+1 (same number of matvecs as in using the Arnoldi
      ! to compute an orthogonalised basis)
      ! but by doing a QR on K_m+1, the norm of r_0 will be in the first row/col position of R, and 
      ! then we can use the other columns of R as they will be the QR of A K_m
      ! That way we only have to do a single reduction in parallel
      ! This is equivalent to computing the gmres polynomial coefficients for 
      ! a single step (s=1) communication avoiding GMRES
      ! Using the power basis is a bad idea at high order due to stability issues, but 
      ! we are staying low order so should be fine  (e.g, < 10th order)
      ! ~~~~~~~~~

      ! ~~~~~~~~~~
      ! Allocate space and create random numbers 
      ! The first vec has random numbers in it
      ! ~~~~~~~~~~      
      call create_temp_space_box_muller(matrix, subspace_size, V_n)

      ! ~~~~~~~~~~~~

      ! Now loop through and build the power basis K_m+1
      do i_loc = 1, subspace_size

         ! Compute V_n(j+1) = A * V_n(j)
         ! Could do this with a matrix-power kernel with less comms if desired, except
         ! that we only ever need this once for very low order so that would prob result in more comms overall
         call MatMult(matrix, &
                  V_n(i_loc), &
                  V_n(i_loc+1), ierr)  
      end do      

      ! Need to copy the individual vectors into a dense slab of memory
      ! Used to just have a dense slab of memory and then
      ! place the pointers into the vecs, but that 
      ! became cumbersome when supporting different vec types (eg cuda on a gpu)
      allocate(K_m_plus_1_data(local_rows, subspace_size+1))
      allocate(global_indices(local_rows))
      call MatGetOwnershipRange(matrix, global_row_start, global_row_end_plus_one, ierr)  
      do row_i = 1, local_rows
         global_indices(row_i) = global_row_start + row_i - 1
      end do
        
      ! Copy into K_m_plus_1_data and then destroy the vecs
      do i_loc = 1, subspace_size+1
         ! Have to use vecgetvalues interface for gpus
         ! This does a copy of the vec from gpu to cpu if necessary
         call VecGetValues(V_n(i_loc), local_rows, global_indices, K_m_plus_1_data(:, i_loc), ierr)
      end do
      vecs_needed = subspace_size + 1
      call VecDestroyVecs(vecs_needed, V_n, ierr)         

      ! ~~~~~~~~~~~~~
      ! Start the tall-skinny QR factorisation of the power basis - this all happens
      ! on the cpu
      ! ~~~~~~~~~~~~~
      call start_tsqr(MPI_COMM_MATRIX, K_m_plus_1_data, buffers)

      ! ~~~~~
      ! ~~~~~
      ! Now have to call finish_gmres_polynomial_coefficients_power outside this routine
      ! to resolve the async comms in the tsqr
      ! ~~~~~
      ! ~~~~~

      deallocate(K_m_plus_1_data, global_indices)    

   end subroutine start_gmres_polynomial_coefficients_power 

! -------------------------------------------------------------------------------------------------------------------------------

subroutine  finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)
      
      ! Finishes the non-blocking all reduce from start_gmres_polynomial_coefficients_power in parallel
      ! The polynomial coefficients will be output into coefficients

      ! ~~~~~~
      integer, intent(in)                                      :: poly_order
      type(tsqr_buffers), target, intent(inout)                :: buffers
      PetscReal, dimension(:), intent(inout)                        :: coefficients
 
      integer :: subspace_size, n_size, iwork_size
      integer :: errorcode
      ! BLAS/LAPACK integer arguments must be PetscBLASInt
      PetscBLASInt :: lwork, rank, info
      PetscBLASInt :: m_bl, n_bl, nrhs_bl, lda_bl, ldb_bl
      PetscBLASInt, dimension(:), allocatable :: iwork
      PetscReal, dimension(poly_order+2) :: g0, s
      PetscReal, dimension(:), allocatable :: work
      PetscReal, dimension(:,:), pointer :: R_pointer
      PetscReal :: rcond = -1d0

      ! ~~~~~

      ! We call build_gmres_polynomial_inverse to build our neumann polynomials
      ! but they don't need to calculate coefficients, so this skips this routine
      if (.NOT. allocated(buffers%R_buffer_receive)) return

      ! This is how many columns we have in K_m
      subspace_size = poly_order + 1      

      ! Finish the asynchronous wait for the tsqr
      ! This will fill buffers%R_buffer_receive with [n_size R(:,:)] from our tsqr
      call finish_tsqr_parallel(buffers)
      ! This should be the same size as subspace_size + 1
      n_size = int(buffers%R_buffer_receive(1))
      if (n_size /= subspace_size + 1) then
         print *, "ERROR in sizes in TSQR"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if

      ! Point directly at the R block
      ! NOTE: this raw pointer remap ties R_pointer (PetscReal) to the TSQR
      ! R_buffer_receive. The whole TSQR -> coefficients chain is deliberately kept
      ! PetscReal (see docs/plan); any future PetscScalar retype must treat TSQR.F90
      ! and this finish path as one atomic unit.
      R_pointer(1:n_size, 1:n_size) => buffers%R_buffer_receive(2:n_size * n_size + 1)
      g0 = 0      
      ! We know beta is in the top left of R
      g0(1) = R_pointer(1, 1)   
      
      ! We've now finished orthogonalising, let's solve our least squares system
      allocate(work(1))
      allocate(iwork(1))
      lwork = -1

      ! Now we are using dgelsd here as there is no guarantee our power basis will be full rank
      ! eg if our matrix is a (scaled) version of the identity, our columns in the power basis
      ! will be very close (given the random rhs)
      ! to orthogonal and dgels fails without full rank
      ! Start from the second column in R_pointer
      ! Kind-correct BLAS integer dimensions
      m_bl = subspace_size+1
      n_bl = subspace_size
      nrhs_bl = 1
      lda_bl = subspace_size+1
      ldb_bl = size(g0)
      call PFLAREgelsd(m_bl, n_bl, nrhs_bl, R_pointer(1, 2), lda_bl, &
                     g0, ldb_bl, s, rcond, rank, &
                     work, lwork, iwork, info)
      ! Workspace query returns optimal sizes in work(1)/iwork(1); int() is exact
      ! for all plausible sizes < 2^24 even when work is single precision
      lwork = int(work(1))
      iwork_size = iwork(1)
      deallocate(work, iwork)
      allocate(work(lwork))
      allocate(iwork(iwork_size))
      call PFLAREgelsd(m_bl, n_bl, nrhs_bl, R_pointer(1, 2), lda_bl, &
                     g0, ldb_bl, s, rcond, rank, &
                     work, lwork, iwork, info)
      deallocate(work, iwork)

      if (info /= 0) then
         print *, "LS solve failed"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if  
      
      ! These are the polynomial coefficients
      coefficients = g0(1:subspace_size)      

      ! Deallocate the receive buffer
      if (allocated(buffers%R_buffer_receive)) deallocate(buffers%R_buffer_receive)    

   end subroutine  finish_gmres_polynomial_coefficients_power  
   
!------------------------------------------------------------------------------------------------------------------------
   
   subroutine mat_mult_powers_share_sparsity(matrix, poly_order, poly_sparsity_order, buffers, coefficients, &
                  reuse_mat, reuse_submatrices, cmat)

      ! Wrapper around mat_mult_powers_share_sparsity_cpu and mat_mult_powers_share_sparsity_kokkos     
   
      ! ~~~~~~~~~~
      ! Input 
      type(tMat), target, intent(in)                     :: matrix
      integer, intent(in)                                :: poly_order, poly_sparsity_order
      type(tsqr_buffers), intent(inout)                  :: buffers
      PetscReal, dimension(:), target, intent(inout)     :: coefficients
      type(tMat), intent(inout)                          :: reuse_mat, cmat
      type(tMat), dimension(:), pointer, intent(inout)   :: reuse_submatrices

#if defined(PETSC_HAVE_KOKKOS)                     
      integer(c_long_long) :: A_array, B_array, reuse_array
      integer :: errorcode, reuse_int_cmat, reuse_int_reuse_mat
      PetscErrorCode :: ierr
      MatType :: mat_type
      Mat :: temp_mat, temp_mat_reuse, temp_mat_compare
      PetscScalar :: normy
      logical :: reuse_triggered_cmat, reuse_triggered_reuse_mat
      type(c_ptr)  :: coefficients_ptr
      type(tMat) :: reuse_mat_cpu
      type(tMat), dimension(:), pointer :: reuse_submatrices_cpu
      type(tVec) :: max_vec
      PetscInt :: row_loc      
#endif      
      ! ~~~~~~~~~~

      ! ~~~~~~~~~~
      ! Special case if we just want to return a gmres polynomial with the sparsity of the diagonal
      ! This is like a damped Jacobi
      ! ~~~~~~~~~~
if (poly_sparsity_order == 0) then

      call build_gmres_polynomial_inverse_0th_order_sparsity(matrix, poly_order, buffers, &
               coefficients, cmat)     

      return
end if

#if defined(PETSC_HAVE_KOKKOS)    

      call MatGetType(matrix, mat_type, ierr)
      if (mat_type == MATMPIAIJKOKKOS .OR. mat_type == MATSEQAIJKOKKOS .OR. &
            mat_type == MATAIJKOKKOS) then      
               
         ! Finish off the non-blocking all reduce to compute our coefficients
         ! This is a fortran routine and we don't want to call this inside the kokkos
         call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)                

         A_array = matrix%v             
         reuse_triggered_cmat = .NOT. PetscObjectIsNull(cmat) 
         reuse_triggered_reuse_mat = .NOT. PetscObjectIsNull(reuse_mat) 
         reuse_int_cmat = 0
         if (reuse_triggered_cmat) then
            reuse_int_cmat = 1
            B_array = cmat%v
         end if
         reuse_int_reuse_mat = 0
         if (reuse_triggered_reuse_mat) then
            reuse_int_reuse_mat = 1
         end if         
         reuse_array = reuse_mat%v
         coefficients_ptr = c_loc(coefficients)
         ! The kokkos version doesn't take the buffers, we finish all the async stuff before
         ! the kokkos routine is called
         call mat_mult_powers_share_sparsity_kokkos(A_array, poly_order, poly_sparsity_order, &
                  coefficients_ptr, reuse_int_reuse_mat, reuse_array, reuse_int_cmat, B_array)
                         
         reuse_mat%v = reuse_array
         cmat%v = B_array

         ! If debugging do a comparison between CPU and Kokkos results
         if (kokkos_debug()) then

            ! If we're doing reuse and debug, then we have to always output the result 
            ! from the cpu version, as it will have coo preallocation structures set
            ! They aren't copied over if you do a matcopy (or matconvert)
            ! If we didn't do that the next time we come through this routine 
            ! and try to call the cpu version with reuse, it will segfault
            if (reuse_triggered_cmat) then
               temp_mat = cmat
               call MatConvert(cmat, MATSAME, MAT_INITIAL_MATRIX, temp_mat_compare, ierr)  
            else
               temp_mat_compare = cmat                         
            end if            

            ! Debug check if the CPU and Kokkos versions are the same
            ! We send in an empty reuse_mat_cpu here always, as we can't pass through
            ! the same one Kokkos uses as it now only gets out the non-local rows we need
            ! (ie reuse_mat and reuse_mat_cpu are no longer the same size)
            reuse_submatrices_cpu => null()
            call mat_mult_powers_share_sparsity_cpu(matrix, poly_order, poly_sparsity_order, &
                     buffers, coefficients, reuse_mat_cpu, reuse_submatrices_cpu, temp_mat)
            call destroy_matrix_reuse(reuse_mat_cpu, reuse_submatrices_cpu)         
                     
            call MatConvert(temp_mat, MATSAME, MAT_INITIAL_MATRIX, &
                        temp_mat_reuse, ierr)                        

            call MatAXPYWrapper(temp_mat_reuse, PFLARE_MINUS_ONE, temp_mat_compare)
            ! Find the biggest entry in the difference
            call MatCreateVecs(temp_mat_reuse, PETSC_NULL_VEC, max_vec, ierr)
            call MatGetRowMaxAbs(temp_mat_reuse, max_vec, PETSC_NULL_INTEGER_POINTER, ierr)
            call VecMax(max_vec, row_loc, normy, ierr)
            call VecDestroy(max_vec, ierr)

            ! There is floating point compute in these inverses, so we have to be a 
            ! bit more tolerant to rounding differences
            if (normy .gt. PFLARE_TOL_MATFREE_4EM11 .OR. normy/=normy) then
               !call MatFilter(temp_mat_reuse, 1d-14, PETSC_TRUE, PETSC_FALSE, ierr)
               !call MatView(temp_mat_reuse, PETSC_VIEWER_STDOUT_WORLD, ierr)
               print *, "Diff Kokkos and CPU mat_mult_powers_share_sparsity", normy, "row", row_loc

               call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)  
            end if
            call MatDestroy(temp_mat_reuse, ierr)
            if (.NOT. reuse_triggered_cmat) then
               call MatDestroy(cmat, ierr)
            else
               call MatDestroy(temp_mat_compare, ierr)
            end if
            cmat = temp_mat
         end if

      else

         call mat_mult_powers_share_sparsity_cpu(matrix, poly_order, poly_sparsity_order, &
                  buffers, coefficients, reuse_mat, reuse_submatrices, cmat)       

      end if
#else
      call mat_mult_powers_share_sparsity_cpu(matrix, poly_order, poly_sparsity_order, &
                  buffers, coefficients, reuse_mat, reuse_submatrices, cmat)
#endif         

      ! ~~~~~~~~~~
      
   end subroutine mat_mult_powers_share_sparsity

!------------------------------------------------------------------------------------------------------------------------
   
   subroutine mat_mult_powers_share_sparsity_cpu(matrix, poly_order, poly_sparsity_order, buffers, coefficients, &
                  reuse_mat, reuse_submatrices, cmat)

      ! Compute matrix powers c = coeff(1) * I + coeff(2) * A + coeff(3) * A^2 + coeff(4) * A^3 + ... 
      ! where a c and the powers all share the same sparsity as the power input in poly_sparsity_order
      ! This also finishes the async comms required to compute the gmres poly coefficients if buffers%request is allocated
   
      ! ~~~~~~~~~~
      ! Input 
      type(tMat), target, intent(in)                     :: matrix
      integer, intent(in)                                :: poly_order, poly_sparsity_order
      type(tsqr_buffers), intent(inout)                  :: buffers
      PetscReal, dimension(:), intent(inout)             :: coefficients
      type(tMat), intent(inout)                          :: reuse_mat, cmat
      type(tMat), dimension(:), pointer, intent(inout)   :: reuse_submatrices
      
      PetscInt :: local_rows, local_cols, global_rows, global_cols
      PetscInt :: global_row_start, global_row_end_plus_one, row_index_into_submatrix
      PetscInt :: global_col_start, global_col_end_plus_one, n, ncols, ncols_two, ifree, max_nnzs
      PetscInt :: i_loc, j_loc, row_size, rows_ao, cols_ao, rows_ad, cols_ad, shift = 0
      integer :: errorcode, match_counter, term, order
      integer :: comm_size
      PetscErrorCode :: ierr      
      integer, dimension(:), allocatable :: cols_index_one, cols_index_two
      PetscInt, dimension(:), allocatable :: col_indices_off_proc_array, ad_indices, cols
      ! Matrix entries filled by MatGetRow are PetscScalar
      PetscScalar, dimension(:), allocatable :: vals
      type(tIS), dimension(1) :: col_indices, row_indices
      type(tMat) :: Ad, Ao
      PetscInt, dimension(:), pointer :: colmap
      logical :: deallocate_submatrices = .FALSE.
      type(tMat), dimension(size(coefficients)-1), target :: matrix_powers
      type(tMat), pointer :: mat_sparsity_match
      type(int_vec), dimension(:), allocatable :: symbolic_ones
      type(real_vec), dimension(:), allocatable :: symbolic_vals
      integer(c_long_long) A_array
      MPIU_Comm :: MPI_COMM_MATRIX
      PetscReal, dimension(:), allocatable :: vals_power_temp, vals_previous_power_temp
      PetscInt, dimension(:), pointer :: submatrices_ia, submatrices_ja, cols_two_ptr, cols_ptr
      ! Matrix entries filled by MatSeqAIJGetArray/MatGetRow are PetscScalar
      PetscScalar, dimension(:), pointer :: vals_two_ptr, vals_ptr
      PetscScalar, pointer :: submatrices_vals(:)
      logical :: reuse_triggered
      PetscBool :: symmetric = PETSC_FALSE, inodecompressed = PETSC_FALSE, done
      PetscInt, parameter :: one = 1, zero = 0
      
      ! ~~~~~~~~~~  

      if (poly_sparsity_order .ge. size(coefficients)-1) then      
         print *, "Requested sparsity is greater than or equal to the order"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if      

      call PetscObjectGetComm(matrix, MPI_COMM_MATRIX, ierr)    
      ! Get the comm size 
      call MPI_Comm_size(MPI_COMM_MATRIX, comm_size, errorcode)

      ! Get the local sizes
      call MatGetLocalSize(matrix, local_rows, local_cols, ierr)
      call MatGetSize(matrix, global_rows, global_cols, ierr)
      ! This returns the global index of the local portion of the matrix
      call MatGetOwnershipRange(matrix, global_row_start, global_row_end_plus_one, ierr)  
      call MatGetOwnershipRangeColumn(matrix, global_col_start, global_col_end_plus_one, ierr)  

      reuse_triggered = .NOT. PetscObjectIsNull(cmat) 

      ! ~~~~~~~~~~
      ! Compute any matrix powers we might need to constrain sparsity and start assembling the 
      ! components of the output matrix up to the order of poly_sparsity_order
      ! The powers higher than poly_sparsity_order can be done with only
      ! a single bit of comms and is done below this
      ! ~~~~~~~~~~

      ! matrix_powers stores all the powers of the input matrix
      matrix_powers(1) = matrix

      ! What power of A do we want to match the sparsity of
      ! Compute the power we need if we're two or above
      do order = 2, poly_sparsity_order

         ! Let's just store each power, that way we can set the sparsity 
         ! as the highest (unconstrained) power and do the mataxpy with a subset of entries
         ! Takes more memory to do this but is faster
         call MatMatMult(matrix, matrix_powers(order-1), &
               MAT_INITIAL_MATRIX, PFLARE_MATMULT_FILL, matrix_powers(order), ierr)        
      end do  
      
      ! mat_sparsity_match now contains the sparsity of the power of A we want to match
      mat_sparsity_match => matrix_powers(poly_sparsity_order)

      ! Copy in the highest unconstrained power
      ! Duplicate & copy the matrix, but ensure there is a diagonal present
      call mat_duplicate_copy_plus_diag(matrix_powers(poly_sparsity_order), reuse_triggered, cmat)

      ! We know we will never have non-zero locations outside of the highest constrained sparsity power 
      call MatSetOption(cmat, MAT_NEW_NONZERO_LOCATION_ERR, PETSC_TRUE,  ierr)     
      call MatSetOption(cmat, MAT_NEW_NONZERO_ALLOCATION_ERR, PETSC_TRUE,  ierr) 
      ! We know we are only going to insert local vals
      ! These options should turn off any reductions in the assembly
      call MatSetOption(cmat, MAT_NO_OFF_PROC_ENTRIES, PETSC_TRUE, ierr)     
      
      ! ~~~~~~~~~~~~
      ! If we're in parallel we need to get the off-process rows of matrix that correspond
      ! to the columns of mat_sparsity_match
      ! We can therefore do the matmult for every constrained power locally with just that data
      ! ~~~~~~~~~~~~
      ! Have to double check comm_size /= 1 as we might be on a subcommunicator and we can't call
      ! MatMPIAIJGetSeqAIJ specifically if that's the case
      if (comm_size /= 1) then

         ! ~~~~
         ! Get the cols
         ! ~~~~
         call MatMPIAIJGetSeqAIJ(mat_sparsity_match, Ad, Ao, colmap, ierr)

         call MatGetSize(Ad, rows_ad, cols_ad, ierr)             
         ! We know the col size of Ao is the size of colmap, the number of non-zero offprocessor columns
         call MatGetSize(Ao, rows_ao, cols_ao, ierr)         

         ! For the column indices we need to take all the columns of mat_sparsity_match
         A_array = mat_sparsity_match%v

         ! These are the global indices of the columns we want
         allocate(col_indices_off_proc_array(cols_ad + cols_ao))
         allocate(ad_indices(cols_ad))
         ! Local rows (as global indices)
         do ifree = 1, cols_ad
            ad_indices(ifree) = global_row_start + ifree - 1
         end do

         ! col_indices_off_proc_array is now sorted, which are the global indices of the columns we want
         call merge_pre_sorted(ad_indices, colmap, col_indices_off_proc_array)
         deallocate(ad_indices)

         ! Create the sequential IS we want with the cols we want (written as global indices)
         call ISCreateGeneral(PETSC_COMM_SELF, cols_ad + cols_ao, &
                     col_indices_off_proc_array, PETSC_USE_POINTER, col_indices(1), ierr) 
         call ISCreateGeneral(PETSC_COMM_SELF, cols_ao, &
                     colmap, PETSC_USE_POINTER, row_indices(1), ierr)                      

         ! ~~~~~~~
         ! Now we can pull out the chunk of matrix that we need
         ! ~~~~~~~

         ! We need off-processor rows to compute matrix powers   
         ! Setting this is necessary to avoid an allreduce when calling createsubmatrices
         ! This will be reset to false after the call to createsubmatrices
         call MatSetOption(matrix, MAT_SUBMAT_SINGLEIS, PETSC_TRUE, ierr)       
         
         ! Now this will be doing comms to get the non-local rows we want
         ! But only including the columns of the local fixed sparsity, as we don't need all the 
         ! columns of the non-local entries unless we are doing a full matmatmult
         ! This returns a sequential matrix
         if (.NOT. PetscObjectIsNull(reuse_mat)) then
            reuse_submatrices(1) = reuse_mat
            call MatCreateSubMatrices(matrix, one, row_indices, col_indices, MAT_REUSE_MATRIX, reuse_submatrices, ierr)
         else
            call MatCreateSubMatrices(matrix, one, row_indices, col_indices, MAT_INITIAL_MATRIX, reuse_submatrices, ierr)
            reuse_mat = reuse_submatrices(1)
         end if
         row_size = size(col_indices_off_proc_array)
         call ISDestroy(col_indices(1), ierr)
         call ISDestroy(row_indices(1), ierr)

      ! Easy in serial as we have everything we neeed
      else

         Ad = mat_sparsity_match
         cols_ad = local_cols
         allocate(reuse_submatrices(1))
         deallocate_submatrices = .TRUE.
         reuse_submatrices(1) = matrix
         row_size = local_rows
         allocate(col_indices_off_proc_array(local_rows))
         do ifree = 1, local_rows
            col_indices_off_proc_array(ifree) = ifree-1
         end do
      end if   
      
      ! ~~~~~~~~~
      ! Now that we are here, reuse_submatrices(1) contains A^poly_sparsity_order with all of the rows
      ! that correspond to the non-zero columns of matrix
      ! ~~~~~~~~~      

      ! Have to get the max nnzs of the local and off-local rows we've just retrieved
      max_nnzs = 0
      do ifree = global_row_start, global_row_end_plus_one-1     
         call MatGetRow(matrix, ifree, ncols, PETSC_NULL_INTEGER_POINTER, PETSC_NULL_SCALAR_POINTER, ierr)
         if (ncols > max_nnzs) max_nnzs = ncols
         call MatRestoreRow(matrix, ifree, ncols, PETSC_NULL_INTEGER_POINTER, PETSC_NULL_SCALAR_POINTER, ierr)
      end do      
      if (comm_size /= 1) then
         do ifree = 1, cols_ao            
            call MatGetRow(reuse_submatrices(1), ifree-1, ncols, PETSC_NULL_INTEGER_POINTER, PETSC_NULL_SCALAR_POINTER, ierr)
            if (ncols > max_nnzs) max_nnzs = ncols
            call MatRestoreRow(reuse_submatrices(1), ifree-1, ncols, PETSC_NULL_INTEGER_POINTER, PETSC_NULL_SCALAR_POINTER, ierr)
         end do
      end if
      ! and also the sparsity power
      do ifree = global_row_start, global_row_end_plus_one-1     
         call MatGetRow(mat_sparsity_match, ifree, ncols, PETSC_NULL_INTEGER_POINTER, PETSC_NULL_SCALAR_POINTER, ierr)
         if (ncols > max_nnzs) max_nnzs = ncols
         call MatRestoreRow(mat_sparsity_match, ifree, ncols, PETSC_NULL_INTEGER_POINTER, PETSC_NULL_SCALAR_POINTER, ierr)
      end do 
      
      ! ~~~~~~~~
      ! Get pointers to the sequential aij structure so we don't have to put critical regions
      ! around the matgetrow
      ! ~~~~~~~~
      call MatGetRowIJ(reuse_submatrices(1),shift,symmetric,inodecompressed,n,submatrices_ia,submatrices_ja,done,ierr) 
      if (.NOT. done) then
         print *, "Pointers not set in call to MatGetRowIJF"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if
      ! Read-only access to the value array - the read variant doesn't bump
      ! the matrix object state, so passing in e.g. a pc->pmat won't trigger
      ! a spurious pc re-setup on every iteration
      call MatSeqAIJGetArrayRead(reuse_submatrices(1), submatrices_vals, ierr)
      
      ! ~~~~~~~~~~
      
      allocate(cols(max_nnzs))
      allocate(vals(max_nnzs))
      allocate(vals_power_temp(max_nnzs))
      allocate(vals_previous_power_temp(max_nnzs))
      allocate(cols_index_one(max_nnzs))
      allocate(cols_index_two(max_nnzs))      

      ! ~~~~~~~~~~~      
      ! Finish the non-blocking all-reduce and compute our polynomial coefficients
      ! ~~~~~~~~~~~
      call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)

      ! Scale the highest constrained power
      call MatScale(cmat, coefficients(poly_sparsity_order+1), ierr)

      ! Then go backwards and add in each of the coefficients * A^order from the second highest order down
      do order = poly_sparsity_order - 1, 1, -1

         ! Do result = alpha_1 * A_ff + alpha_2 * A_ff^2 + ....
         ! Can use SUBSET_NONZERO_PATTERN as we have put the highest order power in first
         call MatAXPY(cmat, coefficients(order+1), matrix_powers(order), SUBSET_NONZERO_PATTERN , ierr) 
      end do 

      ! Add in the 0th order term
      do i_loc = 1, local_rows   
         
         ! Add in the I term - 0th order term
         call MatSetValue(cmat, global_row_start + i_loc-1, global_row_start + i_loc-1, &
                     coefficients(1), ADD_VALUES, ierr)           
      end do

      ! ~~~~~~~~~~~~
      ! From here we now have cmat with the correct values up to the power poly_sparsity_order
      ! and hence we want to add in the sparsity constrained powers
      ! ~~~~~~~~~~~~
      
      ! Now go through and compute the sum of the matrix powers
      ! We're doing row-wise matmatmults here assuming the fixed sparsity
      ! We exploit the fact that the subsequent matrix powers can be done
      ! one row at a time, so we only have to retrieve the needed vals from mat_sparsity_match once
      do i_loc = 1, local_rows 
                          
         ! Get the row of mat_sparsity_match
         call MatGetRow(mat_sparsity_match, i_loc - 1 + global_row_start, ncols_two, &
                  cols_ptr, vals_ptr, ierr)
         ! Copying here because mat_sparsity_match and matrix are often the same matrix
         ! and hence we can only have one active matgetrow
         ncols = ncols_two
         cols(1:ncols) = cols_ptr(1:ncols)
         vals(1:ncols) = vals_ptr(1:ncols)
         call MatRestoreRow(mat_sparsity_match, i_loc - 1 + global_row_start, ncols_two, &
                  cols_ptr, vals_ptr, ierr)         

         ! This is just a symbolic for the set of rows given in cols
         ! Let's just do all the column matching and extraction of the values once
            
         ! Allocate some space to store the matching indices
         allocate(symbolic_ones(ncols))
         allocate(symbolic_vals(ncols))
         row_index_into_submatrix = 1

         ! This is a row-wise product
         do j_loc = 1, ncols

            ! If we're trying to access a local row in matrix
            if (cols(j_loc) .ge. global_row_start .AND. cols(j_loc) < global_row_end_plus_one) then

               call MatGetRow(matrix, cols(j_loc), ncols_two, &
                        cols_two_ptr, vals_two_ptr, ierr)

            ! If we're trying to access a non-local row in matrix
            else

               ! this is local row index we want into reuse_submatrices(1) (as row_indices used to extract are just colmap)  
               ! We know cols is sorted, so every non-local index will be greater than the last one
               ! (it's just that cols could have some local ones between different non-local)
               ! colmap is also sorted and we know every single non-local entry in cols(j_loc) is in colmap
               do while (row_index_into_submatrix .le. cols_ao .AND. colmap(row_index_into_submatrix) .lt. cols(j_loc))
                  row_index_into_submatrix = row_index_into_submatrix + 1
               end do

               ! This is the number of columns
               ncols_two = submatrices_ia(row_index_into_submatrix+1) - submatrices_ia(row_index_into_submatrix)
               allocate(cols_two_ptr(ncols_two))
               ! This is the local column indices in reuse_submatrices(1)
               cols_two_ptr = submatrices_ja(submatrices_ia(row_index_into_submatrix)+1:submatrices_ia(row_index_into_submatrix+1))
               ! Because col_indices_off_proc_array (and hence the column indices in reuse_submatrices(1) is sorted, 
               ! then cols_two_ptr contains the sorted global column indices
               cols_two_ptr = col_indices_off_proc_array(cols_two_ptr+1)

               ! This is the values
               vals_two_ptr => &
                submatrices_vals(submatrices_ia(row_index_into_submatrix)+1:submatrices_ia(row_index_into_submatrix+1))
            end if
            
            ! Search for the matching column
            ! We're intersecting the global column indices of mat_sparsity_match (cols) and matrix (cols_two_ptr)
            call intersect_pre_sorted_indices_only(cols(1:ncols), cols_two_ptr, cols_index_one, cols_index_two, match_counter)      
            
            ! Don't need to do anything if we have no matches
            if (match_counter == 0) then 
               ! Store that we can skip this entry
               symbolic_ones(j_loc)%ptr => null()
               symbolic_vals(j_loc)%ptr => null()                        
            else

               ! These are the matching local column indices for this row of mat_sparsity_match
               allocate(symbolic_ones(j_loc)%ptr(match_counter))
               symbolic_ones(j_loc)%ptr = cols_index_one(1:match_counter)

               ! These are the matching values of matrix
               allocate(symbolic_vals(j_loc)%ptr(match_counter))
               symbolic_vals(j_loc)%ptr = vals_two_ptr(cols_index_two(1:match_counter)) 
            end if   
            
            ! Restore local row of matrix
            if (cols(j_loc) .ge. global_row_start .AND. cols(j_loc) < global_row_end_plus_one) then
               call MatRestoreRow(matrix, cols(j_loc), ncols_two, &
                        cols_two_ptr, vals_two_ptr, ierr)
            else
               deallocate(cols_two_ptr)
            end if            
         end do
         
         ! Start with the values of mat_sparsity_match in it
         vals_previous_power_temp(1:ncols) = vals(1:ncols)
                     
         ! Loop over any matrix powers
         ! vals_power_temp stores the value of A^(term-1) for this row, and we update this as we go through 
         ! the term loop
         do term = poly_sparsity_order+2, size(coefficients)

            ! We need to sum up the product of vals_previous_power_temp(j_loc) * matching columns
            vals_power_temp(1:ncols) = 0

            ! Have to finish all the columns before we move onto the next coefficient
            do j_loc = 1, ncols

               ! If we have no matching columns cycle this row
               if (.NOT. associated(symbolic_ones(j_loc)%ptr)) cycle

               ! symbolic_vals(j_loc)%ptr has the matching values of A in it
               vals_power_temp(symbolic_ones(j_loc)%ptr) = vals_power_temp(symbolic_ones(j_loc)%ptr) + &
                        vals_previous_power_temp(j_loc) * symbolic_vals(j_loc)%ptr

            end do
               
            ! ~~~~~~~~~~~
            ! Now can add the value of coeff * A^(term-1) to our matrix
            ! Can skip this if coeff is zero, but still need to compute A^(term-1)
            ! for the next time through
            ! ~~~~~~~~~~~
            if (ncols /= 0 .AND. coefficients(term) /= 0d0) then
               call MatSetValues(cmat, one, [global_row_start + i_loc-1], ncols, cols, &
                     coefficients(term) * vals_power_temp(1:ncols), ADD_VALUES, ierr)   
            end if

            ! This should now have the value of A^(term-1) in it
            vals_previous_power_temp(1:ncols) = vals_power_temp(1:ncols)
         end do      

         ! Delete our symbolic
         do j_loc = 1, ncols
            if (associated(symbolic_ones(j_loc)%ptr)) then
               deallocate(symbolic_ones(j_loc)%ptr)
               deallocate(symbolic_vals(j_loc)%ptr)
            end if      
         end do  
         deallocate(symbolic_vals, symbolic_ones)  
      end do

      call MatRestoreRowIJ(reuse_submatrices(1),shift,symmetric,inodecompressed,n,submatrices_ia,submatrices_ja,done,ierr)
      call MatSeqAIJRestoreArrayRead(reuse_submatrices(1), submatrices_vals, ierr)

      ! ~~~~~~~~~~~

      ! Do the assembly, should need zero reductions in this given we've set the 
      ! flags above
      call MatAssemblyBegin(cmat, MAT_FINAL_ASSEMBLY, ierr)

      ! Delete temporaries
      do order = 2, poly_sparsity_order
         call MatDestroy(matrix_powers(order), ierr)
      end do
      if (deallocate_submatrices) then
         deallocate(reuse_submatrices)
         reuse_submatrices => null()
      end if

      deallocate(col_indices_off_proc_array)
      deallocate(cols, vals, vals_power_temp, vals_previous_power_temp, cols_index_one, cols_index_two)

      ! Finish assembly
      call MatAssemblyEnd(cmat, MAT_FINAL_ASSEMBLY, ierr) 

   end subroutine mat_mult_powers_share_sparsity_cpu

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine build_gmres_polynomial_inverse(matrix, poly_order, buffers, coefficients, &
                  poly_sparsity_order, matrix_free, diag_scale_polys, reuse_mat, reuse_submatrices, inv_matrix)

      ! Assembles a matrix which is an approximation to the inverse of a matrix using the 
      ! gmres polynomial coefficients 
      ! This finishes the async comms required to compute the coefficients as late as possible
      ! Can constrain the sparsity to that an arbritrary matrix power of the input by setting
      ! poly_sparsity_order < poly_order

      ! ~~~~~~
      type(tMat), intent(in)                            :: matrix
      integer, intent(in)                               :: poly_order
      type(tsqr_buffers), intent(inout)                 :: buffers
      PetscReal, dimension(:), target, intent(inout)    :: coefficients
      integer, intent(in)                               :: poly_sparsity_order
      logical, intent(in)                               :: matrix_free, diag_scale_polys
      type(tMat), intent(inout)                         :: reuse_mat, inv_matrix
      type(tMat), dimension(:), pointer, intent(inout)  :: reuse_submatrices

      ! Local variables
      PetscInt :: global_row_start, global_row_end_plus_one
      PetscInt :: global_rows, global_cols, local_rows, local_cols
      integer :: comm_size, errorcode, order
      PetscErrorCode :: ierr
      MPIU_Comm :: MPI_COMM_MATRIX
      VecType :: vtype
      type(tMat) :: mat_power, temp_mat, diag_scaled_mat
      type(tVec) :: diag_inverse_vec
      type(mat_ctxtype), pointer :: mat_ctx=>null(), mat_ctx_scaled=>null()
      logical :: reuse_triggered      

      ! ~~~~~~       

      ! We might want to call the gmres poly creation on a sub communicator
      ! so let's get the comm attached to the matrix and make sure to use that 
      call PetscObjectGetComm(matrix, MPI_COMM_MATRIX, ierr)    
      ! Get the comm size 
      call MPI_Comm_size(MPI_COMM_MATRIX, comm_size, errorcode)        

      ! Get the local sizes
      call MatGetLocalSize(matrix, local_rows, local_cols, ierr)
      call MatGetSize(matrix, global_rows, global_cols, ierr)
      ! This returns the global index of the local portion of the matrix
      call MatGetOwnershipRange(matrix, global_row_start, global_row_end_plus_one, ierr)
      
      ! Just build a matshell that applies our polynomial matrix-free
      if (matrix_free) then

         ! Finish off the non-blocking all reduce to compute our coefficients
         call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)

         ! If not re-using
         if (PetscObjectIsNull(inv_matrix)) then

            ! Have to dynamically allocate this
            allocate(mat_ctx)         

            ! We pass in the polynomial coefficients as the context
            call MatCreateShell(MPI_COMM_MATRIX, local_rows, local_cols, global_rows, global_cols, &
                        mat_ctx, inv_matrix, ierr)
            if (diag_scale_polys) then
               ! The subroutine petsc_matvec_right_scale_poly_mf applies
               ! q(mat_ctx%mat_scaled) D^-1
               call MatShellSetOperation(inv_matrix, &
                           MATOP_MULT, petsc_matvec_right_scale_poly_mf, ierr)              
            else
               ! The subroutine petsc_matvec_poly_mf applies the polynomial inverse, q(mat_ctx%mat)
               call MatShellSetOperation(inv_matrix, &
                           MATOP_MULT, petsc_matvec_poly_mf, ierr)
            end if
            ! The subroutine petsc_matvec_poly_transpose_mf applies the transpose of
            ! whichever of the two above we just set - it builds a transposed twin of
            ! this matshell on demand, see ensure_transpose_mat
            call MatShellSetOperation(inv_matrix, &
                        MATOP_MULT_TRANSPOSE, petsc_matvec_poly_transpose_mf, ierr)

            call MatAssemblyBegin(inv_matrix, MAT_FINAL_ASSEMBLY, ierr)
            call MatAssemblyEnd(inv_matrix, MAT_FINAL_ASSEMBLY, ierr) 
            ! Have to make sure to set the type of vectors the shell creates
            call MatGetVecType(matrix, vtype, ierr)
            call MatShellSetVecType(inv_matrix, vtype, ierr)

            ! Create temporary vector we use during horner
            ! Make sure to use matrix here to get the right type (as the shell doesn't know about gpus)            
            call MatCreateVecs(matrix, mat_ctx%mf_temp_vec(MF_VEC_TEMP), PETSC_NULL_VEC, ierr)        
            
            ! Need to build mat_ctx%mat_scaled, ie D^-1 A
            if (diag_scale_polys) then

               ! Have to dynamically allocate this
               allocate(mat_ctx_scaled)
               mat_ctx_scaled%coefficients => coefficients                     
               
               ! Create the matshell
               call MatCreateShell(MPI_COMM_MATRIX, local_rows, local_cols, global_rows, global_cols, &
                           mat_ctx_scaled, mat_ctx%mat_scaled, ierr)
               ! The subroutine petsc_matvec_da_poly_mf applies D^-1 A
               call MatShellSetOperation(mat_ctx%mat_scaled, &
                           MATOP_MULT, petsc_matvec_da_poly_mf, ierr)

               call MatAssemblyBegin(mat_ctx%mat_scaled, MAT_FINAL_ASSEMBLY, ierr)
               call MatAssemblyEnd(mat_ctx%mat_scaled, MAT_FINAL_ASSEMBLY, ierr)   
               ! Have to make sure to set the type of vectors the shell creates
               call MatGetVecType(matrix, vtype, ierr)
               call MatShellSetVecType(mat_ctx%mat_scaled, vtype, ierr)
               
               ! Create temporary vector we use during horner
               ! Make sure to use matrix here to get the right type (as the shell doesn't know about gpus)            
               call MatCreateVecs(matrix, mat_ctx%mf_temp_vec(MF_VEC_RHS), mat_ctx%mf_temp_vec(MF_VEC_DIAG), ierr)                 

            end if

         ! Reusing 
         else
            call MatShellGetContext(inv_matrix, mat_ctx, ierr)
            if (diag_scale_polys) then
               call MatShellGetContext(mat_ctx%mat_scaled, mat_ctx_scaled, ierr)
            end if
         end if

         ! Free old owned coefficients before reassigning.
         ! Avoids a memory leak when the same matshell is reused across PCSetUp calls
         ! (SAME_NONZERO_PATTERN) but fresh coefficients are being computed.
         ! For PCAIR, own_coefficients is always .FALSE., so this is a no-op there.
         if (mat_ctx%own_coefficients .AND. associated(mat_ctx%coefficients)) then
            deallocate(mat_ctx%coefficients)
            mat_ctx%coefficients => null()
         end if
         
         ! This is the matrix whose inverse we are applying (just copying the pointer here)
         mat_ctx%mat = matrix 
         mat_ctx%coefficients => coefficients
         if (diag_scale_polys) then
            mat_ctx_scaled%mat = matrix 

            ! Get the diagonal
            call MatGetDiagonal(matrix, mat_ctx%mf_temp_vec(MF_VEC_DIAG), ierr)    
            mat_ctx_scaled%mf_temp_vec(MF_VEC_DIAG) = mat_ctx%mf_temp_vec(MF_VEC_DIAG)
         end if

         ! We're done
         return
      end if

      ! ~~~~~~~~~~~~
      ! If we're here then we want an assembled approximate inverse
      ! ~~~~~~~~~~~~
      reuse_triggered = .NOT. PetscObjectIsNull(inv_matrix) 

      ! If we want to diagonally scale (ie apply Jacobi preconditioned gmres polynomial)
      if (diag_scale_polys) then
         call MatCreateVecs(matrix, PETSC_NULL_VEC, diag_inverse_vec, ierr)
         call MatGetDiagonal(matrix, diag_inverse_vec, ierr)
         call VecReciprocal(diag_inverse_vec, ierr)
         call MatDuplicate(matrix, MAT_COPY_VALUES, diag_scaled_mat, ierr)
         call MatDiagonalScale(diag_scaled_mat, diag_inverse_vec, PETSC_NULL_VEC, ierr) 

      else
         diag_scaled_mat = matrix
      end if      

      ! If we're zeroth order poly this is trivial as it's just the coefficient(1) on the diagonal
      if (poly_order == 0) then

         call build_gmres_polynomial_inverse_0th_order(diag_scaled_mat, poly_order, buffers, coefficients, &
               inv_matrix)         

         if (diag_scale_polys) then
            call MatDestroy(diag_scaled_mat, ierr)
            call MatDiagonalScale(inv_matrix, PETSC_NULL_VEC, diag_inverse_vec, ierr)  
            call VecDestroy(diag_inverse_vec, ierr)      
         end if         

         ! Then just return
         return

      ! For poly_order 1 and poly_sparsity_order 1 this is easy
      else if (poly_order == 1 .AND. poly_sparsity_order == 1) then

         ! Duplicate & copy the matrix, but ensure there is a diagonal present
         call mat_duplicate_copy_plus_diag(diag_scaled_mat, reuse_triggered, inv_matrix)

         ! Flags to prevent reductions when assembling (there are assembles in the shift)
         call MatSetOption(inv_matrix, MAT_NO_OFF_PROC_ENTRIES, PETSC_TRUE, ierr) 
         call MatSetOption(inv_matrix, MAT_NEW_NONZERO_LOCATION_ERR, PETSC_TRUE,  ierr)     
         call MatSetOption(inv_matrix, MAT_NEW_NONZERO_ALLOCATION_ERR, PETSC_TRUE,  ierr)                   

         ! Finish off the non-blocking all reduce to compute our coefficients
         call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)

         ! result = alpha_1 * A_ff
         call MatScale(inv_matrix, coefficients(2), ierr)
         ! Now have to go through and add alpha_0 to the other terms
         ! Don't need an assemble as there is one called in this
         call MatShift(inv_matrix, coefficients(1), ierr)       

         if (diag_scale_polys) then
            call MatDestroy(diag_scaled_mat, ierr)
            call MatDiagonalScale(inv_matrix, PETSC_NULL_VEC, diag_inverse_vec, ierr)  
            call VecDestroy(diag_inverse_vec, ierr)      
         end if         

         ! Then just return
         return

      end if    

      ! If we're constraining sparsity we've built a custom matrix-powers that assumes fixed sparsity
      if (poly_sparsity_order < poly_order) then       
               
         ! This routine is a custom one that builds our matrix powers and assumes fixed sparsity
         ! so that it doen't have to do much comms
         ! This also finishes off the asyn comms and computes the coefficients
         call mat_mult_powers_share_sparsity(diag_scaled_mat, poly_order, poly_sparsity_order, buffers, coefficients, &
                  reuse_mat, reuse_submatrices, inv_matrix)

         if (diag_scale_polys) then
            call MatDestroy(diag_scaled_mat, ierr)
            call MatDiagonalScale(inv_matrix, PETSC_NULL_VEC, diag_inverse_vec, ierr)  
            call VecDestroy(diag_inverse_vec, ierr)      
         end if                  

         ! Then just return
         return

      end if

      ! ~~~~~~~~~~
      ! We are only here if we don't constrain_sparsity
      ! ~~~~~~~~~~

      ! If not re-using
      ! Copy in the initial matrix
      if (.NOT. reuse_triggered) then
         ! Duplicate & copy the matrix, but ensure there is a diagonal present
         call mat_duplicate_copy_plus_diag(diag_scaled_mat, .FALSE., inv_matrix)
      else
         ! For the powers > 1 the pattern of the original matrix will be different
         ! to the resulting inverse
         call MatCopy(diag_scaled_mat, inv_matrix, DIFFERENT_NONZERO_PATTERN, ierr)
      end if

      ! Don't set any off processor entries so no need for a reduction when assembling
      call MatSetOption(inv_matrix, MAT_NO_OFF_PROC_ENTRIES, PETSC_TRUE, ierr)  
      
      ! Finish off the non-blocking all reduce to compute our coefficients
      call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)

      ! result = alpha_1 * A_ff
      call MatScale(inv_matrix, coefficients(2), ierr)

      ! ~~~~~~~~~~~~~
      ! For terms 2nd order and higher
      ! ~~~~~~~~~~~~~   

      do order = 2, poly_order

         ! Skip this term if the coefficient is zero
         if (coefficients(order+1) == 0d0) cycle

         ! TODO - these can be reused
         if (order == 2) then
            call MatMatMult(diag_scaled_mat, diag_scaled_mat, &
                  MAT_INITIAL_MATRIX, PFLARE_MATMULT_FILL, temp_mat, ierr)     
         else
            call MatMatMult(diag_scaled_mat, mat_power, &
                  MAT_INITIAL_MATRIX, PFLARE_MATMULT_FILL, temp_mat, ierr)      
            call MatDestroy(mat_power, ierr)
         end if       

         ! Copy the temporary into mat_power
         call MatDuplicate(temp_mat, MAT_COPY_VALUES, mat_power, ierr)
         call MatDestroy(temp_mat, ierr)

         ! Do result = alpha_1 * A_ff + alpha_2 * A_ff^2 + ....
         if (reuse_triggered) then
            ! If doing reuse we know our nonzeros are a subset
            call MatAXPY(inv_matrix, coefficients(order+1), mat_power, SUBSET_NONZERO_PATTERN, ierr)
         else
            ! Have to use the DIFFERENT_NONZERO_PATTERN here
            call MatAXPYWrapper(inv_matrix, coefficients(order+1), mat_power)
         end if
      end do
      ! Don't forget to destroy the last power
      call MatDestroy(mat_power, ierr)

      ! The alpha_0 just gets added to the diagonal
      ! There is an assemble in the shift so don't need a separate one       
      call MatShift(inv_matrix, coefficients(1), ierr)  
      
      if (diag_scale_polys) then
         call MatDestroy(diag_scaled_mat, ierr)
         call MatDiagonalScale(inv_matrix, PETSC_NULL_VEC, diag_inverse_vec, ierr)  
         call VecDestroy(diag_inverse_vec, ierr)      
      end if      

   end subroutine build_gmres_polynomial_inverse
   
! -------------------------------------------------------------------------------------------------------------------------------

   subroutine build_gmres_polynomial_inverse_0th_order(matrix, poly_order, buffers, coefficients, &
                  inv_matrix)

      ! Specific 0th order inverse

      ! ~~~~~~
      type(tMat), intent(in)                            :: matrix
      integer, intent(in)                               :: poly_order
      type(tsqr_buffers), intent(inout)                 :: buffers
      PetscReal, dimension(:), target, intent(inout)    :: coefficients
      type(tMat), intent(inout)                         :: inv_matrix

      ! Local variables
      integer :: errorcode
      PetscErrorCode :: ierr      
      logical :: reuse_triggered
      type(tVec) :: diag_vec   

      ! ~~~~~~      
      
      if (poly_order /= 0) then
         print *, "This is a 0th order inverse, but poly_order is not 0"
         call MPI_Abort(MPI_COMM_WORLD, MPI_ERR_OTHER, errorcode)
      end if

      ! Let's create a matrix to represent the inverse diagonal
      reuse_triggered = .NOT. PetscObjectIsNull(inv_matrix)       

      if (.NOT. reuse_triggered) then
         call MatCreateVecs(matrix, PETSC_NULL_VEC, diag_vec, ierr)
      else
         call MatDiagonalGetDiagonal(inv_matrix, diag_vec, ierr)
      end if
      
      ! Finish off the non-blocking all reduce to compute our coefficients
      call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)
      call VecSet(diag_vec, coefficients(1), ierr)

      ! We may be reusing with the same sparsity
      if (.NOT. reuse_triggered) then
         ! The matrix takes ownership of diag_vec and increases ref counter
         call MatCreateDiagonal(diag_vec, inv_matrix, ierr)
         call VecDestroy(diag_vec, ierr)
      else
         call MatDiagonalRestoreDiagonal(inv_matrix, diag_vec, ierr)
      end if             

   end subroutine build_gmres_polynomial_inverse_0th_order

! -------------------------------------------------------------------------------------------------------------------------------

   subroutine build_gmres_polynomial_inverse_0th_order_sparsity(matrix, poly_order, buffers, coefficients, &
                  inv_matrix)

      ! Specific inverse with 0th order sparsity

      ! ~~~~~~
      type(tMat), intent(in)                            :: matrix
      integer, intent(in)                               :: poly_order
      type(tsqr_buffers), intent(inout)                 :: buffers
      PetscReal, dimension(:), target, intent(inout)    :: coefficients
      type(tMat), intent(inout)                         :: inv_matrix

      ! Local variables
      integer :: order
      PetscErrorCode :: ierr      
      logical :: reuse_triggered
      type(tVec) :: inv_vec, diag_vec, power_vec
      ! ~~~~~~

      reuse_triggered = .NOT. PetscObjectIsNull(inv_matrix)

       ! Our matrix has to be square
      call MatCreateVecs(matrix, power_vec, diag_vec, ierr)
      call MatGetDiagonal(matrix, diag_vec, ierr)

      ! This stores D^order
      if (.NOT. reuse_triggered) then
         call VecDuplicate(diag_vec, inv_vec, ierr)
      else
         call MatDiagonalGetDiagonal(inv_matrix, inv_vec, ierr)
      end if
      call VecCopy(diag_vec, power_vec, ierr)

      ! ~~~~~~~~~~~      
      ! Finish the non-blocking all-reduce and compute our polynomial coefficients
      ! ~~~~~~~~~~~
      call finish_gmres_polynomial_coefficients_power(poly_order, buffers, coefficients)         

      ! Set: alpha_0 * I
      call VecSet(inv_vec, coefficients(1), ierr)

      ! Calculate: alpha_0 * I + alpha_1 * D + alpha_2 * D^2
      do order = 1, poly_order
         call VecAXPY(inv_vec, coefficients(order+1), power_vec, ierr)
         ! Compute power_vec = power_vec * D
         if (order /= poly_order) call VecPointwiseMult(power_vec, power_vec, diag_vec, ierr)
      end do

      ! We may be reusing with the same sparsity
      if (.NOT. reuse_triggered) then
         ! The matrix takes ownership of inv_vec and increases ref counter
         call MatCreateDiagonal(inv_vec, inv_matrix, ierr)
         call VecDestroy(inv_vec, ierr)
      else
         call MatDiagonalRestoreDiagonal(inv_matrix, inv_vec, ierr)
      end if  

      call VecDestroy(diag_vec, ierr)
      call VecDestroy(power_vec, ierr)                      

   end subroutine build_gmres_polynomial_inverse_0th_order_sparsity    

! -------------------------------------------------------------------------------------------------------------------------------

end module gmres_poly

