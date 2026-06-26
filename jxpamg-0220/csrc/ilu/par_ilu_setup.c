#include "jx_parilu.h"
#include "jx_krylov.h"
#include "jx_util.h"
#include "jx_mv.h"
#include <float.h>

#define JX_USING_CUDA 1
#define JX_USING_GPU 1
/*--------------------------------------------------------------------------
 * jx_ILUSetup
 *--------------------------------------------------------------------------*/

JX_Int
jx_ILUSetup(void *ilu_vdata, jx_ParCSRMatrix *A, jx_ParVector *f, jx_ParVector *u)
{
    MPI_Comm comm = jx_ParCSRMatrixComm(A);
    // JX_MemoryLocation  memory_location     = jx_ParCSRMatrixMemoryLocation(A);
    jx_ParILUData *ilu_data = (jx_ParILUData *)ilu_vdata;
    //    jx_ParILUData     *schur_precond_ilu;
    //    jx_ParNSHData     *schur_solver_nsh;

    /* Pointers to ilu data */
    JX_Int logging = jx_ParILUDataLogging(ilu_data);
    JX_Int print_level = jx_ParILUDataPrintLevel(ilu_data);
    JX_Int ilu_type = jx_ParILUDataIluType(ilu_data);
    JX_Int nLU = jx_ParILUDataNLU(ilu_data);
    JX_Int nI = jx_ParILUDataNI(ilu_data);
    JX_Int fill_level = jx_ParILUDataLfil(ilu_data);
    JX_Int sweep = jx_ParILUDatasweep(ilu_data);
    JX_Int max_row_elmts = jx_ParILUDataMaxRowNnz(ilu_data);
    JX_Real *droptol = jx_ParILUDataDroptol(ilu_data);
    JX_Int *CF_marker_array = jx_ParILUDataCFMarkerArray(ilu_data);
    JX_Int *perm = jx_ParILUDataPerm(ilu_data);
    JX_Int *qperm = jx_ParILUDataQPerm(ilu_data);
    JX_Real tol_ddPQ = jx_ParILUDataTolDDPQ(ilu_data);

    jx_ParCSRMatrix *matA = jx_ParILUDataMatA(ilu_data);
    jx_ParCSRMatrix *matL = jx_ParILUDataMatL(ilu_data);
    JX_Real *matD = jx_ParILUDataMatD(ilu_data);
    jx_ParCSRMatrix *matU = jx_ParILUDataMatU(ilu_data);
    jx_ParCSRMatrix *matmL = jx_ParILUDataMatLModified(ilu_data);
    JX_Real *matmD = jx_ParILUDataMatDModified(ilu_data);
    jx_ParCSRMatrix *matmU = jx_ParILUDataMatUModified(ilu_data);
    jx_ParCSRMatrix *matS = jx_ParILUDataMatS(ilu_data);
    JX_Int n = jx_CSRMatrixNumRows(jx_ParCSRMatrixDiag(A));
    JX_Int reordering_type = jx_ParILUDataReorderingType(ilu_data);
    JX_Real nnzS; /* Total nnz in S */
    JX_Real nnzS_offd_local;
    JX_Real nnzS_offd;
    JX_Int size_C /* Total size of coarse grid */;

    jx_ParVector *Utemp = NULL;
    jx_ParVector *Ftemp = NULL;
    jx_ParVector *Xtemp = NULL;
    jx_ParVector *Ytemp = NULL;
    jx_ParVector *Ztemp = NULL;
    JX_Real *uext = NULL;
    JX_Real *fext = NULL;
    jx_ParVector *rhs = NULL;
    jx_ParVector *x = NULL;

    /* TODO (VPM): Change F_array and U_array variable names */
    jx_ParVector *D_array = jx_ParILUDataD(ilu_data);
    jx_ParVector *F_array = jx_ParILUDataF(ilu_data);
    jx_ParVector *U_array = jx_ParILUDataU(ilu_data);
    jx_ParVector *residual = jx_ParILUDataResidual(ilu_data);
    JX_Real *rel_res_norms = jx_ParILUDataRelResNorms(ilu_data);

    /* might need for Schur Complement */
    JX_Int *u_end = NULL;
    //    JX_Solver          schur_solver         = NULL;
    //    JX_Solver          schur_precond        = NULL;
    //    JX_Solver          schur_precond_gotten = NULL;

    /* Whether or not to use exact (direct) triangular solves */
    JX_Int tri_solve = jx_ParILUDataTriSolve(ilu_data);

    /* help to build external */
    jx_ParCSRCommPkg *comm_pkg;
    JX_Int buffer_size;
    JX_Int num_sends;
    JX_Int send_size;
    JX_Int recv_size;
    JX_Int num_procs, my_id;

    jx_MPI_Comm_size(comm, &num_procs);
    jx_MPI_Comm_rank(comm, &my_id);

    /* Free previously allocated data, if any not destroyed */
    jx_ParCSRMatrixDestroy(matL);
    matL = NULL;
    jx_ParCSRMatrixDestroy(matU);
    matU = NULL;
    jx_ParCSRMatrixDestroy(matmL);
    matmL = NULL;
    jx_ParCSRMatrixDestroy(matmU);
    matmU = NULL;
    jx_ParCSRMatrixDestroy(matS);
    matS = NULL;

    // jx_ParVectorDestroy(D_array); D_array = NULL;

    for (JX_Int i = 0; i < jx_ParILUDataL_num_levels(ilu_data); i++)
    {
        jx_TFree(jx_ParILUDataL_levels(ilu_data)[i]);
    }
    jx_TFree(jx_ParILUDataL_levels(ilu_data));
    jx_TFree(jx_ParILUDataL_level_sizes(ilu_data));
    jx_ParILUDataL_num_levels(ilu_data) = 0;

    for (JX_Int i = 0; i < jx_ParILUDataU_num_levels(ilu_data); i++)
    {
        jx_TFree(jx_ParILUDataU_levels(ilu_data)[i]);
    }
    jx_TFree(jx_ParILUDataU_levels(ilu_data));
    jx_TFree(jx_ParILUDataU_level_sizes(ilu_data));
    jx_ParILUDataU_num_levels(ilu_data) = 0;

    jx_TFree(matD);
    jx_TFree(matmD);
    jx_TFree(CF_marker_array);

    /* clear old l1_norm data, if created */
    jx_TFree(jx_ParILUDataL1Norms(ilu_data));

    /* setup temporary storage
     * first check is they've already here
     */
    jx_ParVectorDestroy(jx_ParILUDataUTemp(ilu_data));
    jx_ParVectorDestroy(jx_ParILUDataFTemp(ilu_data));
    jx_ParVectorDestroy(jx_ParILUDataRhs(ilu_data));
    jx_ParVectorDestroy(jx_ParILUDataX(ilu_data));
    jx_ParVectorDestroy(jx_ParILUDataResidual(ilu_data));
    jx_TFree(jx_ParILUDataUExt(ilu_data));
    jx_TFree(jx_ParILUDataFExt(ilu_data));
    jx_TFree(jx_ParILUDataUEnd(ilu_data));
    jx_TFree(jx_ParILUDataRelResNorms(ilu_data));

    jx_ParILUDataUTemp(ilu_data) = NULL;
    jx_ParILUDataFTemp(ilu_data) = NULL;
    jx_ParILUDataRhs(ilu_data) = NULL;
    jx_ParILUDataX(ilu_data) = NULL;
    jx_ParILUDataResidual(ilu_data) = NULL;

    /* Create work vectors */
    Utemp = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
                               jx_ParCSRMatrixGlobalNumRows(A),
                               jx_ParCSRMatrixRowStarts(A));
    jx_ParVectorInitialize(Utemp);
    jx_ParILUDataUTemp(ilu_data) = Utemp;

    Ftemp = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
                               jx_ParCSRMatrixGlobalNumRows(A),
                               jx_ParCSRMatrixRowStarts(A));
    jx_ParVectorInitialize(Ftemp);
    jx_ParILUDataFTemp(ilu_data) = Ftemp;

    Xtemp = jx_ParVectorCreate(comm, jx_ParVectorGlobalSize(u), jx_ParVectorPartitioning(u));
   jx_ParVectorInitialize(Xtemp);
   jx_ParILUDataXTemp(ilu_data) = Xtemp;


   Ytemp = jx_ParVectorCreate(comm, jx_ParVectorGlobalSize(u), jx_ParVectorPartitioning(u));
   jx_ParVectorInitialize(Ytemp);
   jx_ParILUDataYTemp(ilu_data) = Ytemp;

    /* set matrix, solution and rhs pointers */
    matA = A;
    F_array = f;
    U_array = u;

    /*层次调度*/
    // JX_Int **L_levels, **U_levels;
    // JX_Int *L_level_sizes, *U_level_sizes;
    // JX_Int L_num_levels, U_num_levels;

    // /* Create perm array if necessary */
    // if (!perm)
    // {
    //    switch (ilu_type)
    //    {
    //       case 0: case 1:
    //       default:
    //          /* RCM or none */
    //          jx_ILUGetLocalPerm(matA, &perm, &nLU, reordering_type);
    //          break;
    //    }
    // }

    /* Factorization */
    switch (ilu_type)
    {
        case 0: /* BJ + jx_iluk() */
        {
            jx_ILUSetupILUK(matA, fill_level, perm, perm, n, n,
                            &matL, &matD, &matU, &D_array, &u_end);
            if (tri_solve == 2)
            {
                jx_CSRMatrixTopologicSortILU(jx_ParCSRMatrixDiag(matL), jx_ParCSRMatrixDiag(matU),
                                            &(ilu_data->nlevL), &(ilu_data->jlevL), &(ilu_data->ilevL),
                                            &(ilu_data->nlevU), &(ilu_data->jlevU), &(ilu_data->ilevU));
            }
            else if (tri_solve == 3)
            {
                jx_GreedyColoring_L(matL, n, &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->nlevL));
                jx_GreedyColoring_U(matU, n, &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->nlevU));
            }
            else if (tri_solve == 12)
            {
                jx_GreedyColoring_L1(matL, n, &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->nlevL), &(ilu_data->L_perm), &(ilu_data->L_iperm));
                jx_GreedyColoring_U1(matU, n, &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->nlevU), &(ilu_data->U_perm), &(ilu_data->U_iperm));
            }
            if (tri_solve == 7)
            {
                jx_CSRMatrixTopologicSortILU(jx_ParCSRMatrixDiag(matL), jx_ParCSRMatrixDiag(matU),
                                            &(ilu_data->nlevL), &(ilu_data->jlevL), &(ilu_data->ilevL),
                                            &(ilu_data->nlevU), &(ilu_data->jlevU), &(ilu_data->ilevU));
            }
            else if (tri_solve == 8)
            {
                jx_GreedyColoring_8GS(matA, n, &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->nlevL), &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->nlevU));
            }
            else if (tri_solve == 13)
            {
                jx_CSRMatrixTopologicSortILU1(jx_ParCSRMatrixDiag(matL), jx_ParCSRMatrixDiag(matU),
                                            &(ilu_data->nlevL), &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->L_perm), &(ilu_data->L_iperm),
                                            &(ilu_data->nlevU), &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->U_perm), &(ilu_data->U_iperm));
            }
        }
        break;

        case 2: /* BJ + jx_iluk() */
        {
            jx_ILUSetupFGPILU_v2(matA, perm, perm, sweep,
                                &matL, &matD, &matU, &D_array, &u_end);
            if (tri_solve == 2)
            {
                jx_CSRMatrixTopologicSortILU(jx_ParCSRMatrixDiag(matL), jx_ParCSRMatrixDiag(matU),
                                            &(ilu_data->nlevL), &(ilu_data->jlevL), &(ilu_data->ilevL),
                                            &(ilu_data->nlevU), &(ilu_data->jlevU), &(ilu_data->ilevU));
            }
            else if (tri_solve == 3)
            {
                jx_GreedyColoring_L(matL, n, &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->nlevL));
                jx_GreedyColoring_U(matU, n, &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->nlevU));
            }
            else if (tri_solve == 12)
            {
                jx_GreedyColoring_L1(matL, n, &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->nlevL), &(ilu_data->L_perm), &(ilu_data->L_iperm));
                jx_GreedyColoring_U1(matU, n, &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->nlevU), &(ilu_data->U_perm), &(ilu_data->U_iperm));
            }
            if (tri_solve == 7)
            {
                jx_CSRMatrixTopologicSortILU(jx_ParCSRMatrixDiag(matL), jx_ParCSRMatrixDiag(matU),
                                            &(ilu_data->nlevL), &(ilu_data->jlevL), &(ilu_data->ilevL),
                                            &(ilu_data->nlevU), &(ilu_data->jlevU), &(ilu_data->ilevU));
            }
            else if (tri_solve == 8)
            {
                jx_GreedyColoring_8GS(matA, n, &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->nlevL), &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->nlevU));
            }
            else if (tri_solve == 13)
            {
                jx_CSRMatrixTopologicSortILU1(jx_ParCSRMatrixDiag(matL), jx_ParCSRMatrixDiag(matU),
                                            &(ilu_data->nlevL), &(ilu_data->jlevL), &(ilu_data->ilevL), &(ilu_data->L_perm), &(ilu_data->L_iperm),
                                            &(ilu_data->nlevU), &(ilu_data->jlevU), &(ilu_data->ilevU), &(ilu_data->U_perm), &(ilu_data->U_iperm));
            }
        }
        break;

        case 3:
        {
            jx_ILUSetupFGPILU_v3(matA, sweep, &matL, &D_array, &matU, &matS, &u_end);
        }
        break;
    }

    // D_array = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
    //                             jx_ParCSRMatrixGlobalNumRows(A),
    //                             jx_ParCSRMatrixRowStarts(A) );
    // jx_ParVectorInitialize(D_array);
    // jx_ParILUDataD(ilu_data) =  D_array;

    // jx_Vector *D_local = jx_ParVectorLocalVector(D_array);
    // JX_Real  *D_data   = jx_VectorData(D_local);
    // for (JX_Int i = 0; i < n; i++)
    // {
    //    D_data[i] = matD[i];
    // }

    // memcpy(jx_VectorData(D_local), D_data, n * sizeof(JX_Real));

    /* Set pointers to ilu data */
    jx_ParILUDataMatA(ilu_data) = matA;
    jx_ParILUDataXTemp(ilu_data) = Xtemp;
    jx_ParILUDataYTemp(ilu_data) = Ytemp;
    jx_ParILUDataZTemp(ilu_data) = Ztemp;
    jx_ParILUDataF(ilu_data) = F_array;
    jx_ParILUDataU(ilu_data) = U_array;
    jx_ParILUDataMatL(ilu_data) = matL;
    jx_ParILUDataMatD(ilu_data) = matD;
    jx_ParILUDataMatU(ilu_data) = matU;
    jx_ParILUDataMatLModified(ilu_data) = matmL;
    jx_ParILUDataMatDModified(ilu_data) = matmD;
    jx_ParILUDataMatUModified(ilu_data) = matmU;
    jx_ParILUDataMatS(ilu_data) = matS;
    jx_ParILUDataCFMarkerArray(ilu_data) = CF_marker_array;
    jx_ParILUDataPerm(ilu_data) = perm;
    jx_ParILUDataQPerm(ilu_data) = qperm;
    jx_ParILUDataNLU(ilu_data) = nLU;
    jx_ParILUDataNI(ilu_data) = nI;
    jx_ParILUDataUEnd(ilu_data) = u_end;
    jx_ParILUDataUExt(ilu_data) = uext;
    jx_ParILUDataFExt(ilu_data) = fext;
    jx_ParILUDataD(ilu_data) = D_array;

    /* compute operator complexity */
    jx_ParCSRMatrixSetDNumNonzeros(matA);
    nnzS = 0.0;

    /* size_C is the size of global coarse grid, upper left part */
    size_C = jx_ParCSRMatrixGlobalNumRows(matA);

    /* TODO (VPM): Move ILU statistics printout to its own function */
    if ((my_id == 0) && (print_level > 0))
    {
        jx_printf("ILU SETUP: operator complexity = %f  \n",
                  jx_ParILUDataOperatorComplexity(ilu_data));
        if (jx_ParILUDataTriSolve(ilu_data) == 1)
        {
            jx_printf("ILU SOLVE: using direct triangular solves\n",
                      jx_ParILUDataOperatorComplexity(ilu_data));
        }
        if (jx_ParILUDataTriSolve(ilu_data) == 2)
        {
            jx_printf("ILU SOLVE: using s triangular solves\n",
                      jx_ParILUDataOperatorComplexity(ilu_data));
        }
        if (jx_ParILUDataTriSolve(ilu_data) == 3)
        {
            jx_printf("ILU SOLVE: using GS iterative triangular solves\n",
                      jx_ParILUDataOperatorComplexity(ilu_data));
        }
    }

    if (logging > 1)
    {
        residual =
            jx_ParVectorCreate(jx_ParCSRMatrixComm(matA),
                               jx_ParCSRMatrixGlobalNumRows(matA),
                               jx_ParCSRMatrixRowStarts(matA));
        jx_ParVectorInitialize(residual);
        jx_ParILUDataResidual(ilu_data) = residual;
    }
    else
    {
        jx_ParILUDataResidual(ilu_data) = NULL;
    }
    rel_res_norms = jx_CTAlloc(JX_Real, jx_ParILUDataMaxIter(ilu_data));
    jx_ParILUDataRelResNorms(ilu_data) = rel_res_norms;

    // jx_GpuProfilingPopRange();

    return jx_error_flag;
}

/*--------------------------------------------------------------------------
 * jx_ILUSetupILUK
 *
 * Setup ILU(k) numeric factorization
 *
 * A: input matrix
 * lfil: level of fill-in, the k in ILU(k)
 * permp: permutation array indicating ordering of factorization.
 *        Perm could come from a CF_marker array or a reordering routine.
 * qpermp: column permutation array.
 * nLU: size of computed LDU factorization.
 * nI: number of interial unknowns, nI should obey nI >= nLU
 * Lptr, Dptr, Uptr: L, D, U factors.
 * Sprt: Schur Complement, if no Schur Complement, it will be set to NULL
 *--------------------------------------------------------------------------*/

JX_Int
jx_ILUSetupILUK(jx_ParCSRMatrix *A,
                JX_Int lfil,
                JX_Int *permp,
                JX_Int *qpermp,
                JX_Int nLU,
                JX_Int nI,
                jx_ParCSRMatrix **Lptr,
                JX_Real **Dptr,
                jx_ParCSRMatrix **Uptr,
                jx_ParVector **D_array,
                JX_Int **u_end)
{
    /*
     * 1: Setup and create buffers
     * matL/U: the ParCSR matrix for L and U
     * L/U_diag: the diagonal csr matrix of matL/U
     * A_diag_*: tempory pointer for the diagonal matrix of A and its '*' slot
     * ii = outer loop from 0 to nLU - 1
     * i = the real col number in diag inside the outer loop
     * iw =  working array store the reverse of active col number
     * iL = working array store the active col number
     */

    /* call ILU0 if lfil is 0 */
    if (lfil == 0)
    {
        // printf("enter jx_ILUSetupILU0 \n");
        return jx_ILUSetupILU0(A, permp, qpermp, nLU, nI, Lptr, Dptr, Uptr, D_array, u_end);
    }

    return jx_error_flag;
}

/*--------------------------------------------------------------------------
 * jx_ILUSetupILU0
 *
 * Setup ILU(0)
 *
 * A = input matrix
 * perm = permutation array indicating ordering of rows.
 *        Perm could come from a CF_marker array or a reordering routine.
 *         When set to NULL, identity permutation is used.
 * qperm = permutation array indicating ordering of columns.
 *         When set to NULL, identity permutation is used.
 * nI = number of interial unknowns
 * nLU = size of incomplete factorization, nLU should obey nLU <= nI.
 *       Schur complement is formed if nLU < n
 * Lptr, Dptr, Uptr, Sptr = L, D, U, S factors.
 * will form global Schur Matrix if nLU < n
 *--------------------------------------------------------------------------*/

JX_Int
jx_ILUSetupILU0(jx_ParCSRMatrix *A,
                JX_Int *perm,
                JX_Int *qperm,
                JX_Int nLU,
                JX_Int nI,
                jx_ParCSRMatrix **Lptr,
                JX_Real **Dptr,
                jx_ParCSRMatrix **Uptr,
                jx_ParVector **D_array,
                JX_Int **u_end)
{
    return jx_ILUSetupMILU0(A, perm, qperm, nLU, nI, Lptr, Dptr, Uptr, D_array, u_end, 0);
}

JX_Int
jx_ILUSetupMILU0(jx_ParCSRMatrix *A,
                 JX_Int *permp,
                 JX_Int *qpermp,
                 JX_Int nLU,
                 JX_Int nI,
                 jx_ParCSRMatrix **Lptr,
                 JX_Real **Dptr,
                 jx_ParCSRMatrix **Uptr,
                 jx_ParVector **D_array,
                 JX_Int **u_end,
                 JX_Int modified)
{
    JX_Int i, ii, j, k, k1, k2, k3, ctrU, ctrL, ctrS;
    JX_Int lenl, lenu, jpiv, col, jpos;
    JX_Int *iw, *iL, *iU;
    JX_Real dd, t, dpiv, lxu, *wU, *wL;
    JX_Real drop;

    /* communication stuffs for S */
    MPI_Comm comm = jx_ParCSRMatrixComm(A);
    JX_Int S_offd_nnz, S_offd_ncols;
    jx_ParCSRCommPkg *comm_pkg;
    jx_ParCSRCommHandle *comm_handle;
    JX_Int num_sends, begin, end;
    JX_Int *send_buf = NULL;
    JX_Int num_procs, my_id;

    /* data objects for A */
    jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
    jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
    JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
    JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
    JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
    // JX_Real               *A_offd_data     = jx_CSRMatrixData(A_offd);
    // JX_Int                *a        = jx_CSRMatrixI(A_offd);
    // JX_Int                *A_offd_j        = jx_CSRMatrixJ(A_offd);
    // JX_MemoryLocation      memory_location = jx_ParCSRMatrixMemoryLocation(A);

    /* size of problem and schur system */
    JX_Int n = jx_CSRMatrixNumRows(A_diag);
    JX_Int m = n - nLU;
    JX_Int e = nI - nLU;
    JX_Int m_e = n - nI;
    JX_Real local_nnz, total_nnz;
    JX_Int *u_end_array;

    /* data objects for L, D, U */
    jx_ParCSRMatrix *matL;
    jx_ParCSRMatrix *matU;
    jx_CSRMatrix *L_diag;
    jx_CSRMatrix *U_diag;
    jx_ParVector *vec_D;
    jx_Vector *D_local;
    JX_Real *D_data, *D1_data;
    JX_Real *L_diag_data;
    JX_Int *L_diag_i;
    JX_Int *L_diag_j;
    JX_Real *U_diag_data;
    JX_Int *U_diag_i;
    JX_Int *U_diag_j;

    /* memory management */
    JX_Int initial_alloc = 0;
    JX_Int capacity_L;
    JX_Int capacity_U;
    JX_Int nnz_A = A_diag_i[n];

    /* reverse permutation array */
    JX_Int *rperm;
    JX_Int *perm, *qperm;

    /* start setup
     * get communication stuffs first
     */
    jx_MPI_Comm_size(comm, &num_procs);
    jx_MPI_Comm_rank(comm, &my_id);
    comm_pkg = jx_ParCSRMatrixCommPkg(A);

    /* setup if not yet built */
    if (!comm_pkg)
    {
        jx_MatvecCommPkgCreate(A);
        comm_pkg = jx_ParCSRMatrixCommPkg(A);
    }

    /* check for correctness */
    if (nLU < 0 || nLU > n)
    {
        jx_error_w_msg(JX_ERROR_ARG, "WARNING: nLU out of range.\n");
    }
    if (e < 0)
    {
        jx_error_w_msg(JX_ERROR_ARG, "WARNING: nLU should not exceed nI.\n");
    }

    /* Allocate memory for u_end array */
    u_end_array = jx_TAlloc(JX_Int, nLU);

    /* Allocate memory for L,D,U,S factors */
    if (n > 0)
    {
        initial_alloc = (JX_Int)(nLU + ceil((nnz_A / 2.0) * nLU / n));
    }
    capacity_L = initial_alloc;
    capacity_U = initial_alloc;

    D_data = jx_TAlloc(JX_Real, n);
    D1_data = jx_TAlloc(JX_Real, n);
    L_diag_i = jx_TAlloc(JX_Int, n + 1);
    L_diag_j = jx_TAlloc(JX_Int, capacity_L);
    L_diag_data = jx_TAlloc(JX_Real, capacity_L);
    U_diag_i = jx_TAlloc(JX_Int, n + 1);
    U_diag_j = jx_TAlloc(JX_Int, capacity_U);
    U_diag_data = jx_TAlloc(JX_Real, capacity_U);
    /* allocate working arrays */
    iw = jx_TAlloc(JX_Int, 3 * n);
    iL = iw + n;
    rperm = iw + 2 * n;
    wL = jx_TAlloc(JX_Real, n);

    ctrU = ctrL = 0;
    L_diag_i[0] = U_diag_i[0] = 0;
    /* set marker array iw to -1 */
    for (i = 0; i < n; i++)
    {
        iw[i] = -1;
    }

    /* get reverse permutation (rperm).
     * create permutation if they are null
     * rperm holds the reordered indexes.
     * rperm only used for column
     */

    if (!permp)
    {
        perm = jx_TAlloc(JX_Int, n);
        for (i = 0; i < n; i++)
        {
            perm[i] = i;
        }
    }
    else
    {
        perm = permp;
    }

    if (!qpermp)
    {
        qperm = jx_TAlloc(JX_Int, n);
        for (i = 0; i < n; i++)
        {
            qperm[i] = i;
        }
    }
    else
    {
        qperm = qpermp;
    }

    for (i = 0; i < n; i++)
    {
        rperm[qperm[i]] = i;
    }

    /*---------  Begin Factorization. Work in permuted space  ----*/
    for (ii = 0; ii < nLU; ii++)
    {
        // get row i
        i = perm[ii];
        // get extents of row i
        k1 = A_diag_i[i];
        k2 = A_diag_i[i + 1];
        // track the drop
        drop = 0.0;

        /*-------------------- unpack L & U-parts of row of A in arrays w */
        iU = iL + ii;
        wU = wL + ii;
        /*--------------------  diagonal entry */
        dd = 0.0;
        lenl = lenu = 0;
        iw[ii] = ii;
        /*-------------------- scan & unwrap column */
        for (j = k1; j < k2; j++)
        {
            col = rperm[A_diag_j[j]];
            t = A_diag_data[j];
            if (col < ii)
            {
                iw[col] = lenl;
                iL[lenl] = col;
                wL[lenl++] = t;
            }
            else if (col > ii)
            {
                iw[col] = lenu;
                iU[lenu] = col;
                wU[lenu++] = t;
            }
            else
            {
                dd = t;
            }
        }

        /* eliminate row */
        /*-------------------------------------------------------------------------
         *  In order to do the elimination in the correct order we must select the
         *  smallest column index among iL[k], k = j, j+1, ..., lenl-1. For ILU(0),
         *  no new fill-ins are expect, so we can pre-sort iL and wL prior to the
         *  entering the elimination loop.
         *-----------------------------------------------------------------------*/
        //      jx_quickSortIR(iL, wL, iw, 0, (lenl-1));
        // jx_qsort3ir(iL, wL, iw, 0, (lenl - 1));
        for (j = 0; j < lenl; j++)
        {
            jpiv = iL[j];
            /* get factor/ pivot element */
            dpiv = wL[j] * D_data[jpiv];
            /* store entry in L */
            wL[j] = dpiv;

            /* zero out element - reset pivot */
            iw[jpiv] = -1;
            /* combine current row and pivot row */
            for (k = U_diag_i[jpiv]; k < U_diag_i[jpiv + 1]; k++)
            {
                col = U_diag_j[k];
                jpos = iw[col];

                /* Only fill-in nonzero pattern (jpos != 0) */
                if (jpos < 0)
                {
                    drop = drop - U_diag_data[k] * dpiv;
                    continue;
                }

                lxu = -U_diag_data[k] * dpiv;
                if (col < ii)
                {
                    /* dealing with L part */
                    wL[jpos] += lxu;
                }
                else if (col > ii)
                {
                    /* dealing with U part */
                    wU[jpos] += lxu;
                    // printf("wU\n",wU[jpos]);
                }
                else
                {
                    /* diagonal update */
                    dd += lxu;
                }
            }
        }
        /* modify when necessary */
        if (modified)
        {
            dd = dd + drop;
        }

        /* restore iw (only need to restore diagonal and U part */
        iw[ii] = -1;
        for (j = 0; j < lenu; j++)
        {
            iw[iU[j]] = -1;
        }

        /* Update LDU factors */
        /* L part */
        /* Check that memory is sufficient */
        if (lenl > 0)
        {
            while ((ctrL + lenl) > capacity_L)
            {
                JX_Int tmp = capacity_L;
                capacity_L = (JX_Int)(capacity_L * EXPAND_FACT + 1);
                L_diag_j = jx_TReAlloc(L_diag_j, JX_Int, capacity_L);
                L_diag_data = jx_TReAlloc(L_diag_data, JX_Real, capacity_L);
            }
            memcpy(&L_diag_j[ctrL], iL, lenl * sizeof(JX_Int));
            memcpy(&L_diag_data[ctrL], wL, lenl * sizeof(JX_Real));
        }
        L_diag_i[ii + 1] = (ctrL += lenl);

        /* diagonal part (we store the inverse) */
        if (abs(dd) < MAT_TOL)
        {
            dd = 1.0e-6;
        }
        D_data[ii] = 1. / dd;

        /* U part */
        /* Check that memory is sufficient */
        if (lenu > 0)
        {
            while ((ctrU + lenu) > capacity_U)
            {
                JX_Int tmp = capacity_U;
                capacity_U = (JX_Int)(capacity_U * EXPAND_FACT + 1);
                U_diag_j = jx_TReAlloc(U_diag_j, JX_Int, capacity_U);
                U_diag_data = jx_TReAlloc(U_diag_data, JX_Real, capacity_U);
            }
            memcpy(&U_diag_j[ctrU], iU, lenu * sizeof(JX_Int));
            memcpy(&U_diag_data[ctrU], wU, lenu * sizeof(JX_Real));
        }
        U_diag_i[ii + 1] = (ctrU += lenu);

        // if (lenu > 0) {
        // printf("Row ii=%d, U部分非零元（共%d个）：\n", ii, lenu);
        // for (j = 0; j < lenu; j++) {
        //    printf("  col=%d, val=%e\n", iU[j], wU[j]);
        // }
        // } else {
        //    printf("Row ii=%d, U部分无非零元\n", ii);
        // }
    }

    matL = jx_ParCSRMatrixCreate(comm,
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A),
                                 0,
                                 ctrL,
                                 0);

    L_diag = jx_ParCSRMatrixDiag(matL);
    jx_CSRMatrixI(L_diag) = L_diag_i;
    if (ctrL)
    {
        jx_CSRMatrixData(L_diag) = L_diag_data;
        jx_CSRMatrixJ(L_diag) = L_diag_j;
    }
    else
    {
        /* we've allocated some memory, so free if not used */
        jx_TFree(L_diag_j);
        jx_TFree(L_diag_data);
    }
    /* store (global) total number of nonzeros */
    local_nnz = (JX_Real)ctrL;
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matL) = total_nnz;

    matU = jx_ParCSRMatrixCreate(comm,
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A),
                                 0,
                                 ctrU,
                                 0);

    U_diag = jx_ParCSRMatrixDiag(matU);
    jx_CSRMatrixI(U_diag) = U_diag_i;
    if (ctrU)
    {
        jx_CSRMatrixData(U_diag) = U_diag_data;
        jx_CSRMatrixJ(U_diag) = U_diag_j;
    }
    else
    {
        /* we've allocated some memory, so free if not used */
        jx_TFree(U_diag_j);
        jx_TFree(U_diag_data);
    }
    /* store (global) total number of nonzeros */
    local_nnz = (JX_Real)ctrU;
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matU) = total_nnz;
    /* free memory */
    jx_TFree(wL);
    jx_TFree(iw);
    if (!permp)
    {
        jx_TFree(perm);
    }
    if (!qpermp)
    {
        jx_TFree(qperm);
    }

    memcpy(D1_data, D_data, n * sizeof(JX_Real));

    vec_D = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
                                jx_ParCSRMatrixGlobalNumRows(A),
                                jx_ParCSRMatrixRowStarts(A) );
    jx_ParVectorInitialize(vec_D);
    D_local = jx_ParVectorLocalVector(vec_D);
    jx_VectorData(D_local) = D1_data;

    /* set matrix pointers */
    *Lptr = matL;
    *Dptr = D_data;
    *D_array = vec_D;
    *Uptr = matU;
    // *Sptr = matS;
    *u_end = u_end_array;

    // char FileNameCoaMat[256];
    // jx_sprintf(FileNameCoaMat, "A_CSR_%d", 1);
    // jx_ParCSRMatrixPrint(A, FileNameCoaMat);
    // jx_sprintf(FileNameCoaMat, "L_CSR_%d", 1);
    // jx_ParCSRMatrixPrint(matL, FileNameCoaMat);
    // jx_sprintf(FileNameCoaMat, "U_CSR_%d", 1);
    // jx_ParCSRMatrixPrint(matU, FileNameCoaMat);

    // FILE    *fp;
    // jx_sprintf(FileNameCoaMat, "D_%d", 1);
    // fp = fopen(FileNameCoaMat, "w");
    // for(j = 0; j < n; j++){
    // jx_fprintf(fp, "%.14e\n", D_data[j]);
    // }
    // fclose(fp);

    return jx_error_flag;
}

JX_Int
jx_ILUSetupFGPILU_v1(jx_ParCSRMatrix *A,
                     JX_Int *permp,
                     JX_Int *qpermp,
                     JX_Int sweep,
                     jx_ParCSRMatrix **Lptr,
                     JX_Real **Dptr,
                     jx_ParCSRMatrix **Uptr,
                     jx_ParCSRMatrix **Sptr,
                     JX_Int **u_end)
{
    /*
     * 1: Setup and create buffers
     * matL/U: the ParCSR matrix for L and U
     * L/U_diag: the diagonal csr matrix of matL/U
     * A_diag_*: temporary pointer for the diagonal matrix of A and its '*' slot
     * ii = outer loop from 0 to nLU - 1
     * i = the real col number in diag inside the outer loop
     * iw = working array store the reverse of active col number
     * iL = working array store the active col number
     */
    MPI_Comm comm = jx_ParCSRMatrixComm(A);
    jx_ParCSRCommPkg *comm_pkg;
    JX_Int num_procs, my_id;
    JX_Real *wU, *wL, t;

    JX_Int ii, i, s, j, k, l, jj, ROW_OMP;
    JX_Int tid;
    JX_Int i_start, i_end, countu, countl, col;
    JX_Int L_nnz = 0, U_nnz = 0;
    /* data objects for A */
    jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
    jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
    JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
    JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
    JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
    JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);
    JX_Int *a = jx_CSRMatrixI(A_offd);
    JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
    JX_Int n = jx_CSRMatrixNumRows(A_diag);
    JX_Real local_nnz, total_nnz;
    JX_Int *u_end_array;

    /* data objects for L, D, U */
    JX_Int *workL, *workU;
    jx_ParCSRMatrix *matL;
    jx_ParCSRMatrix *matU;
    jx_CSRMatrix *L_diag;
    jx_CSRMatrix *U_diag;
    JX_Real *D_data;
    JX_Real *L_diag_data;
    JX_Int *L_diag_i;
    JX_Int *L_diag_j;
    JX_Real *U_diag_data;
    JX_Int *U_diag_i;
    JX_Int *U_diag_j;

    JX_Real *D1_data, *d_data, *d1_data;
    JX_Real *L1_diag_data;
    JX_Real *U1_diag_data;

    JX_Int initial_alloc = 0;
    JX_Int capacity_L;
    JX_Int capacity_U;
    JX_Int nnz_A = A_diag_i[n];
    /* reverse permutation array */
    JX_Int *rperm;
    JX_Int *perm, *qperm;
    JX_Int nt = jx_NumThreads();

    // MPI 初始化
    jx_MPI_Comm_size(comm, &num_procs);
    jx_MPI_Comm_rank(comm, &my_id);
    comm_pkg = jx_ParCSRMatrixCommPkg(A);

    /* setup if not yet built */
    if (!comm_pkg)
    {
        jx_MatvecCommPkgCreate(A);
        comm_pkg = jx_ParCSRMatrixCommPkg(A);
    }

    // 动态调整线程数
    if (n <= 1000)
    {
        nt = 1; // n ≤ e^3, use 1 thread
    }
    else if (n <= 10000)
    {
        nt = 2; // e^3 < n ≤ 10^4, use 2 threads
    }
    else if (n <= 100000)
    {
        nt = 4; // e^4 < n ≤ 10^5, use 4 threads
    }
    else if (n <= 1000000)
    {
        nt = 8; // e^5 < n ≤ 10^6, use 8 threads
    }
    else if (n <= 10000000)
    {
        nt = 16; // e^6 < n ≤ 10^7, use 16 threads
    }
    else if (n <= 100000000)
    {
        nt = 32; // e^7 < n ≤ 10^8, use 32 threads
    }
    else
    {
        nt = 64; // n > e^8, use 64 threads
    }

    // 计算每个线程的行数，向上取整
    ROW_OMP = (n + nt - 1) / nt;

    /* 分配 workL 和 workU 记录每个线程的非零元素前缀和 */
    workL = jx_TAlloc(JX_Int, nt + 1);
    workU = jx_TAlloc(JX_Int, nt + 1);
    for (i = 0; i <= nt; i++)
    {
        workL[i] = 0;
        workU[i] = 0;
    }

// 并行计算 L 和 U 的非零元素数量，避免数据竞争
#pragma omp parallel private(i, j, col, i_start, i_end) num_threads(nt)
    {
        JX_Int tid = omp_get_thread_num();
        JX_Int local_workL = 0, local_workU = 0;
        i_start = tid * ROW_OMP;
        i_end = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
        for (i = i_start; i < i_end; i++)
        {
            for (j = A_diag_i[i]; j < A_diag_i[i + 1]; j++)
            {
                col = A_diag_j[j];
                if (col < i)
                    local_workL++;
                else if (col > i)
                    local_workU++;
            }
        }
        workL[tid + 1] = local_workL;
        workU[tid + 1] = local_workU;
#pragma omp barrier
#pragma omp single
        {
            for (i = 1; i <= nt; i++)
            {
                workL[i] += workL[i - 1];
                workU[i] += workU[i - 1];
            }
        }
    }
    L_nnz = workL[nt];
    U_nnz = workU[nt];

    // 错误检查
    if (L_nnz < 0 || U_nnz < 0)
    {
        printf("Error: Invalid nnz values: L_nnz=%d, U_nnz=%d\n", L_nnz, U_nnz);
        jx_TFree(workL);
        jx_TFree(workU);
        return -1;
    }

    // 分配矩阵数据
    D_data = jx_TAlloc(JX_Real, n);
    d1_data = jx_TAlloc(JX_Real, n);
    d_data = jx_TAlloc(JX_Real, n);
    L_diag_i = jx_TAlloc(JX_Int, n + 1);
    L_diag_j = jx_TAlloc(JX_Int, L_nnz);
    L_diag_data = jx_TAlloc(JX_Real, L_nnz);
    L1_diag_data = jx_TAlloc(JX_Real, L_nnz);
    U_diag_i = jx_TAlloc(JX_Int, n + 1);
    U_diag_j = jx_TAlloc(JX_Int, U_nnz);
    U_diag_data = jx_TAlloc(JX_Real, U_nnz);
    U1_diag_data = jx_TAlloc(JX_Real, U_nnz);

// 初始化 L 和 U 的索引和数据
#pragma omp parallel for private(tid, i, j, col, i_start, i_end, countu, countl, t) num_threads(nt) schedule(static)
    for (tid = 0; tid < nt; tid++)
    {
        countu = 0;
        countl = 0;
        i_start = tid * ROW_OMP;
        i_end = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
        for (i = i_start; i < i_end; i++)
        {
            L_diag_i[i] = workL[tid] + countl;
            U_diag_i[i] = workU[tid] + countu;

            for (j = A_diag_i[i]; j < A_diag_i[i + 1]; j++)
            {
                col = A_diag_j[j];
                t = A_diag_data[j];

                if (col > i)
                {
                    U_diag_j[workU[tid] + countu] = col;
                    U_diag_data[workU[tid] + countu] = t;
                    countu++;
                }
                else if (col < i)
                {
                    L_diag_j[workL[tid] + countl] = col;
                    L_diag_data[workL[tid] + countl] = t;
                    countl++;
                }
                else
                {
                    d_data[i] = t;
                    if (fabs(t) < MAT_TOL)
                    {
                        t = 1.0e-6;
                    }
                    D_data[i] = 1. / t;
                }
            }
        }
    }
    L_diag_i[n] = L_nnz;
    U_diag_i[n] = U_nnz;

    // 复制初始数据
    memcpy(d1_data, d_data, n * sizeof(JX_Real));
    memcpy(L1_diag_data, L_diag_data, L_nnz * sizeof(JX_Real));
    memcpy(U1_diag_data, U_diag_data, U_nnz * sizeof(JX_Real));

    // 调试输出
    if (my_id == 0)
    {
        printf("sweep = %d \n", sweep);
    }

    // ILU 因子分解的多次扫描
    for (s = 0; s < sweep; s++)
    {
#pragma omp parallel num_threads(nt)
        {
// 更新 U 矩阵
#pragma omp for private(ii, j, k, l, jj, col) schedule(static)
            for (ii = 0; ii < n; ii++)
            {
                for (j = U_diag_i[ii]; j < U_diag_i[ii + 1]; j++)
                {
                    U_diag_data[j] = U1_diag_data[j]; // 恢复原始 U 值
                    for (k = L_diag_i[ii]; k < L_diag_i[ii + 1]; k++)
                    {
                        jj = L_diag_j[k];
                        for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++)
                        {
                            if (U_diag_j[l] == U_diag_j[j])
                            {
                                U_diag_data[j] -= L_diag_data[k] * U_diag_data[l];
                            }
                        }
                    }
                }
            }
#pragma omp barrier

// 更新 L 矩阵
#pragma omp for private(ii, j, k, l, jj, col) schedule(static)
            for (ii = 0; ii < n; ii++)
            {
                for (j = L_diag_i[ii]; j < L_diag_i[ii + 1]; j++)
                {
                    L_diag_data[j] = L1_diag_data[j]; // 恢复原始 L 值
                    col = L_diag_j[j];
                    for (k = L_diag_i[ii]; k < L_diag_i[ii + 1]; k++)
                    {
                        if (L_diag_j[k] < col)
                        {
                            jj = L_diag_j[k];
                            for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++)
                            {
                                if (U_diag_j[l] == col)
                                {
                                    L_diag_data[j] -= L_diag_data[k] * U_diag_data[l];
                                }
                            }
                        }
                    }
                    L_diag_data[j] *= D_data[col]; // 按对角线逆缩放
                }
            }
#pragma omp barrier

// 更新对角线 d_data
#pragma omp for private(ii, j, k, l, jj) schedule(static)
            for (ii = 0; ii < n; ii++)
            {
                d_data[ii] = d1_data[ii]; // 初始化为原始对角值
                for (k = L_diag_i[ii]; k < L_diag_i[ii + 1]; k++)
                {
                    jj = L_diag_j[k];
                    for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++)
                    {
                        if (U_diag_j[l] == ii)
                        {
                            d_data[ii] -= L_diag_data[k] * U_diag_data[l];
                            break;
                        }
                    }
                }
            }
#pragma omp barrier

// 更新 D_data
#pragma omp for private(ii, t) schedule(static)
            for (ii = 0; ii < n; ii++)
            {
                t = d_data[ii];
                if (fabs(t) < MAT_TOL)
                {
                    t = 1.0e-6;
                }
                D_data[ii] = 1. / t;
            }
        }
    }

    // 创建 L 矩阵
    matL = jx_ParCSRMatrixCreate(comm,
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A),
                                 0,
                                 L_nnz,
                                 0);

    L_diag = jx_ParCSRMatrixDiag(matL);
    jx_CSRMatrixI(L_diag) = L_diag_i;
    if (L_nnz)
    {
        jx_CSRMatrixData(L_diag) = L_diag_data;
        jx_CSRMatrixJ(L_diag) = L_diag_j;
    }
    else
    {
        jx_TFree(L_diag_j);
        jx_TFree(L_diag_data);
    }
    local_nnz = (JX_Real)L_nnz;
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matL) = total_nnz;

    // 创建 U 矩阵
    matU = jx_ParCSRMatrixCreate(comm,
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A),
                                 0,
                                 U_nnz,
                                 0);

    U_diag = jx_ParCSRMatrixDiag(matU);
    jx_CSRMatrixI(U_diag) = U_diag_i;
    if (U_nnz)
    {
        jx_CSRMatrixData(U_diag) = U_diag_data;
        jx_CSRMatrixJ(U_diag) = U_diag_j;
    }
    else
    {
        jx_TFree(U_diag_j);
        jx_TFree(U_diag_data);
    }
    local_nnz = (JX_Real)U_nnz;
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matU) = total_nnz;

    // 设置输出参数
    *Lptr = matL;
    *Dptr = D_data;
    *Uptr = matU;

    // 释放临时内存
    jx_TFree(workL);
    jx_TFree(workU);
    jx_TFree(L1_diag_data);
    jx_TFree(U1_diag_data);
    jx_TFree(d_data);
    jx_TFree(d1_data);

    return jx_error_flag;
}
// JX_Int jx_ILUSetupFGPILU_v2(jx_ParCSRMatrix  *A, JX_Int  *permp,JX_Int  *qpermp,
//                         JX_Int  sweep,jx_ParCSRMatrix **Lptr,JX_Real **Dptr,
//                         jx_ParCSRMatrix **Uptr, jx_ParVector **D_array, JX_Int  **u_end)

JX_Int jx_ILUSetupFGPILU_v2(jx_ParCSRMatrix *A,
                         JX_Int *permp,
                         JX_Int *qpermp,
                         JX_Int sweep,
                         jx_ParCSRMatrix **Lptr,
                         JX_Real **Dptr,
                         jx_ParCSRMatrix **Uptr,
                         jx_ParVector **D_array,
                         JX_Int **u_end)
{
    MPI_Comm comm = jx_ParCSRMatrixComm(A);
    JX_Int num_procs, my_id;
    jx_ParCSRCommPkg *comm_pkg;
    JX_Int i, s, j, k, l, jj, col, countu, countl, ROW_OMP,temp_idx;
    JX_Int tid, i_start, i_end;
    JX_Real t, local_nnz, total_nnz,temp_data;

    /* Data objects for A */
    jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
    jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
    JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
    JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
    JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
    JX_Int n = jx_CSRMatrixNumRows(A_diag);
    JX_Int nnz_A = A_diag_i[n];

    /* Data objects for L, D, U */
    jx_ParCSRMatrix *matL, *matU;
    jx_CSRMatrix *L_diag, *U_diag;
    JX_Real *D_data, *d_data, *d1_data;
    JX_Real *L_diag_data, *L1_diag_data;
    JX_Int *L_diag_i, *L_diag_j;
    JX_Real *U_diag_data, *U1_diag_data;
    JX_Int *U_diag_i, *U_diag_j;
    JX_Int *workL, *workU;
    JX_Int L_nnz = 0, U_nnz = 0;
    JX_Int nt = jx_NumThreads();

    /* MPI initialization */
    jx_MPI_Comm_size(comm, &num_procs);
    jx_MPI_Comm_rank(comm, &my_id);
    comm_pkg = jx_ParCSRMatrixCommPkg(A);
    if (!comm_pkg) {
        jx_MatvecCommPkgCreate(A);
        comm_pkg = jx_ParCSRMatrixCommPkg(A);
    }

    /* Dynamic thread adjustment */
   //  if (n <= 1000) nt = 1;
   //  else if (n <= 10000) nt = 2;
   //  else if (n <= 100000) nt = 4;
   //  else if (n <= 1000000) nt = 8;
   //  else if (n <= 10000000) nt = 16;
   //  else if (n <= 100000000) nt = 32;
   //  else nt = 64;

    ROW_OMP = (n + nt - 1) / nt;

    /* Allocate workL and workU for non-zero prefix sums */
    workL = jx_TAlloc(JX_Int, nt + 1);
    workU = jx_TAlloc(JX_Int, nt + 1);
    if (!workL || !workU) {
        printf("Error: Memory allocation failed for workL or workU\n");
        jx_TFree(workL);
        jx_TFree(workU);
        return -1;
    }
    for (i = 0; i <= nt; i++) {
        workL[i] = 0;
        workU[i] = 0;
    }

    /* Parallel computation of L and U non-zero counts */
    #pragma omp parallel private(i, j, col, i_start, i_end) num_threads(nt)
    {
        int tid = omp_get_thread_num();
        int local_workL = 0, local_workU = 0;
        i_start = tid * ROW_OMP;
        i_end = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
        for (i = i_start; i < i_end; i++) {
            for (j = A_diag_i[i]; j < A_diag_i[i + 1]; j++) {
                col = A_diag_j[j];
                if (col < i)
                    local_workL++;
                else if (col > i)
                    local_workU++;
            }
        }
        workL[tid + 1] = local_workL;
        workU[tid + 1] = local_workU;
        #pragma omp barrier
        #pragma omp single
        {
            for (i = 1; i <= nt; i++) {
                workL[i] += workL[i - 1];
                workU[i] += workU[i - 1];
            }
        }
    }
    L_nnz = workL[nt];
    U_nnz = workU[nt];

    /* Error checking */
    if (L_nnz < 0 || U_nnz < 0) {
        printf("Error: Invalid nnz values: L_nnz=%d, U_nnz=%d\n", L_nnz, U_nnz);
        jx_TFree(workL);
        jx_TFree(workU);
        return -1;
    }

    /* Allocate matrices */
    D_data = jx_TAlloc(JX_Real, n);
    d_data = jx_TAlloc(JX_Real, n);
    d1_data = jx_TAlloc(JX_Real, n);
    L_diag_i = jx_TAlloc(JX_Int, n + 1);
    U_diag_i = jx_TAlloc(JX_Int, n + 1);
    L_diag_j = jx_TAlloc(JX_Int, L_nnz);
    L_diag_data = jx_TAlloc(JX_Real, L_nnz);
    U_diag_j = jx_TAlloc(JX_Int, U_nnz);
    U_diag_data = jx_TAlloc(JX_Real, U_nnz);
    L1_diag_data = jx_TAlloc(JX_Real, L_nnz);
    U1_diag_data = jx_TAlloc(JX_Real, U_nnz);

    if (!D_data || !d_data || !d1_data || !L_diag_i || !U_diag_i ||
        !L_diag_j || !L_diag_data || !U_diag_j || !U_diag_data ||
        !L1_diag_data || !U1_diag_data) {
        printf("Error: Memory allocation failed for matrices\n");
        jx_TFree(D_data); jx_TFree(d_data); jx_TFree(d1_data);
        jx_TFree(L_diag_i); jx_TFree(U_diag_i);
        jx_TFree(L_diag_j); jx_TFree(L_diag_data);
        jx_TFree(U_diag_j); jx_TFree(U_diag_data);
        jx_TFree(L1_diag_data); jx_TFree(U1_diag_data);
        jx_TFree(workL); jx_TFree(workU);
        return -1;
    }

    /* Initialize L and U indices and data */
    #pragma omp parallel for private(tid, i, j, col, i_start, i_end, countu, countl, t) num_threads(nt) schedule(static)
    for (tid = 0; tid < nt; tid++) {
        countu = 0;
        countl = 0;
        i_start = tid * ROW_OMP;
        i_end = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
        for (i = i_start; i < i_end; i++) {
            L_diag_i[i] = workL[tid] + countl;
            U_diag_i[i] = workU[tid] + countu;

            for (j = A_diag_i[i]; j < A_diag_i[i + 1]; j++) {
                col = A_diag_j[j];
                t = A_diag_data[j];

                if (col > i) {
                    U_diag_j[workU[tid] + countu] = col;
                    U_diag_data[workU[tid] + countu] = t;
                    countu++;
                } else if (col < i) {
                    L_diag_j[workL[tid] + countl] = col;
                    L_diag_data[workL[tid] + countl] = t;
                    countl++;
                } else {
                    d_data[i] = t;
                    if (fabs(t) < MAT_TOL) {
                        t = 1.0e-6;
                    }
                    D_data[i] = 1. / t;
                }
            }
        }
    }
    L_diag_i[n] = L_nnz;
    U_diag_i[n] = U_nnz;

    /* Sort L_diag_j and U_diag_j using insertion sort */
    #pragma omp parallel for private(i, j, k, temp_idx, temp_data) num_threads(nt) schedule(static)
    for (i = 0; i < n; i++) {
        /* Sort L_diag_j and L_diag_data */
        if (L_diag_i[i + 1] > L_diag_i[i]) {
            JX_Int len = L_diag_i[i + 1] - L_diag_i[i];
            for (j = L_diag_i[i] + 1; j < L_diag_i[i + 1]; j++) {
                temp_idx = L_diag_j[j];
                temp_data = L_diag_data[j];
                k = j - 1;
                while (k >= L_diag_i[i] && L_diag_j[k] > temp_idx) {
                    L_diag_j[k + 1] = L_diag_j[k];
                    L_diag_data[k + 1] = L_diag_data[k];
                    k--;
                }
                L_diag_j[k + 1] = temp_idx;
                L_diag_data[k + 1] = temp_data;
            }
        }
        /* Sort U_diag_j and U_diag_data */
        if (U_diag_i[i + 1] > U_diag_i[i]) {
            JX_Int len = U_diag_i[i + 1] - U_diag_i[i];
            for (j = U_diag_i[i] + 1; j < U_diag_i[i + 1]; j++) {
                temp_idx = U_diag_j[j];
                temp_data = U_diag_data[j];
                k = j - 1;
                while (k >= U_diag_i[i] && U_diag_j[k] > temp_idx) {
                    U_diag_j[k + 1] = U_diag_j[k];
                    U_diag_data[k + 1] = U_diag_data[k];
                    k--;
                }
                U_diag_j[k + 1] = temp_idx;
                U_diag_data[k + 1] = temp_data;
            }
        }
    }

    memcpy(d1_data, d_data, n * sizeof(JX_Real));
    memcpy(L1_diag_data, L_diag_data, L_nnz * sizeof(JX_Real));
    memcpy(U1_diag_data, U_diag_data, U_nnz * sizeof(JX_Real));

    /* Debug output */
    if (my_id == 0) {
        printf("sweep = %d \n", sweep);
    }

    /* ILU sweeps */
    for (s = 0; s < sweep; s++) {
        #pragma omp parallel num_threads(nt)
        {
            /* Update U matrix */
            #pragma omp for private(i, j, k, l, jj, col) schedule(static)
            for (i = 0; i < n; i++) {
                for (j = U_diag_i[i]; j < U_diag_i[i + 1]; j++) {
                    U_diag_data[j] = U1_diag_data[j];
                    for (k = L_diag_i[i]; k < L_diag_i[i + 1]; k++) {
                        jj = L_diag_j[k];
                        for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++) {
                            if (U_diag_j[l] == U_diag_j[j]) {
                                U_diag_data[j] -= L_diag_data[k] * U_diag_data[l];
                            }
                        }
                    }
                }
            }
            #pragma omp barrier

            /* Update L matrix */
            #pragma omp for private(i, j, k, l, jj, col) schedule(static)
            for (i = 0; i < n; i++) {
                for (j = L_diag_i[i]; j < L_diag_i[i + 1]; j++) {
                    L_diag_data[j] = L1_diag_data[j];
                    col = L_diag_j[j];
                    for (k = L_diag_i[i]; k < L_diag_i[i + 1]; k++) {
                        if (L_diag_j[k] < col) {
                            jj = L_diag_j[k];
                            for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++) {
                                if (U_diag_j[l] == col) {
                                    L_diag_data[j] -= L_diag_data[k] * U_diag_data[l];
                                }
                            }
                        }
                    }
                    L_diag_data[j] *= D_data[col];
                }
            }
            #pragma omp barrier

            /* Update diagonal d_data */
            #pragma omp for private(i, j, k, l, jj) schedule(static)
            for (i = 0; i < n; i++) {
                d_data[i] = d1_data[i];
                for (k = L_diag_i[i]; k < L_diag_i[i + 1]; k++) {
                    jj = L_diag_j[k];
                    for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++) {
                        if (U_diag_j[l] == i) {
                            d_data[i] -= L_diag_data[k] * U_diag_data[l];
                            break;
                        }
                    }
                }
            }
            #pragma omp barrier

            /* Update D_data */
            #pragma omp for private(i, t) schedule(static)
            for (i = 0; i < n; i++) {
                t = d_data[i];
                if (fabs(t) < MAT_TOL) t = 1.0e-6;
                D_data[i] = 1. / t;
            }
        }
    }

    /* Create L matrix */
    matL = jx_ParCSRMatrixCreate(comm, jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A), 0, L_nnz, 0);
    L_diag = jx_ParCSRMatrixDiag(matL);
    jx_CSRMatrixI(L_diag) = L_diag_i;
    if (L_nnz) {
        jx_CSRMatrixData(L_diag) = L_diag_data;
        jx_CSRMatrixJ(L_diag) = L_diag_j;
    } else {
        jx_TFree(L_diag_j);
        jx_TFree(L_diag_data);
    }
    local_nnz = (JX_Real)L_nnz;
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matL) = total_nnz;

    /* Create U matrix */
    matU = jx_ParCSRMatrixCreate(comm, jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A), 0, U_nnz, 0);
    U_diag = jx_ParCSRMatrixDiag(matU);
    jx_CSRMatrixI(U_diag) = U_diag_i;
    if (U_nnz) {
        jx_CSRMatrixData(U_diag) = U_diag_data;
        jx_CSRMatrixJ(U_diag) = U_diag_j;
    } else {
        jx_TFree(U_diag_j);
        jx_TFree(U_diag_data);
    }
    local_nnz = (JX_Real)U_nnz;
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matU) = total_nnz;

    /* Set output parameters */
    *Lptr = matL;
    *Dptr = D_data;
    *Uptr = matU;
    // *Sptr = NULL;
    *u_end = NULL;

    /* Free temporary memory */
    jx_TFree(workL);
    jx_TFree(workU);
    jx_TFree(d_data);
    jx_TFree(d1_data);
    jx_TFree(L1_diag_data);
    jx_TFree(U1_diag_data);

    return jx_error_flag;
}


// JX_Int jx_ILUSetupFGPILU_v2(jx_ParCSRMatrix  *A, JX_Int  *permp,JX_Int  *qpermp,
//                         JX_Int  sweep,jx_ParCSRMatrix **Lptr,JX_Real **Dptr,
//                         jx_ParCSRMatrix **Uptr, jx_ParVector **D_array, JX_Int  **u_end)
// {
//     MPI_Comm comm = jx_ParCSRMatrixComm(A);
//     JX_Int num_procs, my_id;
//     jx_ParCSRCommPkg *comm_pkg;
//     JX_Int i, s, j, k, l, jj, col, countu, countl, ROW_OMP, temp_idx;
//     JX_Int tid, i_start, i_end;
//     JX_Real t, local_nnz, total_nnz, temp_data;

//     /* Data objects for A */
//     jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//     jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
//     JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
//     JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//     JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
//     JX_Int n = jx_CSRMatrixNumRows(A_diag);
//     JX_Int nnz_A = A_diag_i[n];

//     /* Data objects for L, D, U */
//     jx_ParCSRMatrix *matL, *matU;
//     jx_CSRMatrix *L_diag, *U_diag;
//     JX_Real *D_data, *D1_data, *d_data, *d1_data;
//     JX_Real *L_diag_data, *L1_diag_data,*L2_diag_data;
//     JX_Int *L_diag_i, *L_diag_j;
//     JX_Real *U_diag_data, *U1_diag_data,*U2_diag_data;
//     JX_Int *U_diag_i, *U_diag_j;
//     JX_Int *workL, *workU;
//     JX_Int L_nnz = 0, U_nnz = 0;
//     JX_Int nt = jx_NumThreads();

//     jx_ParVector *vec_D;
//     jx_Vector *D_local;

//     /* MPI initialization */
//     jx_MPI_Comm_size(comm, &num_procs);
//     jx_MPI_Comm_rank(comm, &my_id);
//     comm_pkg = jx_ParCSRMatrixCommPkg(A);
//     if (!comm_pkg)
//     {
//         jx_MatvecCommPkgCreate(A);
//         comm_pkg = jx_ParCSRMatrixCommPkg(A);
//     }

//     ROW_OMP = (n + nt - 1) / nt;

//     /* Allocate workL and workU for non-zero prefix sums */
//     workL = jx_TAlloc(JX_Int, nt + 1);
//     workU = jx_TAlloc(JX_Int, nt + 1);
//     if (!workL || !workU)
//     {
//         printf("Error: Memory allocation failed for workL or workU\n");
//         jx_TFree(workL);
//         jx_TFree(workU);
//         return -1;
//     }
//     for (i = 0; i <= nt; i++)
//     {
//         workL[i] = 0;
//         workU[i] = 0;
//     }

// /* Parallel computation of L and U non-zero counts */
// #pragma omp parallel private(i, j, col, i_start, i_end) num_threads(nt)
//     {
//         JX_Int tid = omp_get_thread_num();
//         JX_Int local_workL = 0, local_workU = 0;
//         i_start = tid * ROW_OMP;
//         i_end = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//         for (i = i_start; i < i_end; i++)
//         {
//             for (j = A_diag_i[i]; j < A_diag_i[i + 1]; j++)
//             {
//                 col = A_diag_j[j];
//                 if (col < i)
//                     local_workL++;
//                 else if (col > i)
//                     local_workU++;
//             }
//         }
//         workL[tid + 1] = local_workL;
//         workU[tid + 1] = local_workU;
// #pragma omp barrier
// #pragma omp single
//         {
//             for (i = 1; i <= nt; i++)
//             {
//                 workL[i] += workL[i - 1];
//                 workU[i] += workU[i - 1];
//             }
//         }
//     }
//     L_nnz = workL[nt];
//     U_nnz = workU[nt];

//     /* Error checking */
//     if (L_nnz < 0 || U_nnz < 0)
//     {
//         printf("Error: Invalid nnz values: L_nnz=%d, U_nnz=%d\n", L_nnz, U_nnz);
//         jx_TFree(workL);
//         jx_TFree(workU);
//         return -1;
//     }

//     /* Allocate matrices */
//     D_data = jx_TAlloc(JX_Real, n);
//     D1_data = jx_TAlloc(JX_Real, n);
//     d_data = jx_TAlloc(JX_Real, n);
//     d1_data = jx_TAlloc(JX_Real, n);
//     L_diag_i = jx_TAlloc(JX_Int, n + 1);
//     U_diag_i = jx_TAlloc(JX_Int, n + 1);
//     L_diag_j = jx_TAlloc(JX_Int, L_nnz);
//     L_diag_data = jx_TAlloc(JX_Real, L_nnz);
//     U_diag_j = jx_TAlloc(JX_Int, U_nnz);
//     U_diag_data = jx_TAlloc(JX_Real, U_nnz);
//     L1_diag_data = jx_TAlloc(JX_Real, L_nnz);
//     U1_diag_data = jx_TAlloc(JX_Real, U_nnz);

//     // //中间变量
//     L2_diag_data = jx_TAlloc(JX_Real, L_nnz);
//     U2_diag_data = jx_TAlloc(JX_Real, U_nnz);

//     if (!D_data || !d_data || !d1_data || !L_diag_i || !U_diag_i ||
//         !L_diag_j || !L_diag_data || !U_diag_j || !U_diag_data ||
//         !L1_diag_data || !U1_diag_data)
//     {
//         printf("Error: Memory allocation failed for matrices\n");
//         jx_TFree(D_data);
//         jx_TFree(d_data);
//         jx_TFree(d1_data);
//         jx_TFree(L_diag_i);
//         jx_TFree(U_diag_i);
//         jx_TFree(L_diag_j);
//         jx_TFree(L_diag_data);
//         jx_TFree(U_diag_j);
//         jx_TFree(U_diag_data);
//         jx_TFree(L1_diag_data);
//         jx_TFree(U1_diag_data);
//         jx_TFree(workL);
//         jx_TFree(workU);
//         return -1;
//     }

// /* Initialize L and U indices and data */
// #pragma omp parallel for private(tid, i, j, col, i_start, i_end, countu, countl, t) num_threads(nt) schedule(static)
//     for (tid = 0; tid < nt; tid++)
//     {
//         countu = 0;
//         countl = 0;
//         i_start = tid * ROW_OMP;
//         i_end = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//         for (i = i_start; i < i_end; i++)
//         {
//             L_diag_i[i] = workL[tid] + countl;
//             U_diag_i[i] = workU[tid] + countu;

//             for (j = A_diag_i[i]; j < A_diag_i[i + 1]; j++)
//             {
//                 col = A_diag_j[j];
//                 t = A_diag_data[j];

//                 if (col > i)
//                 {
//                     U_diag_j[workU[tid] + countu] = col;
//                     U_diag_data[workU[tid] + countu] = t;
//                     countu++;
//                 }
//                 else if (col < i)
//                 {
//                     L_diag_j[workL[tid] + countl] = col;
//                     L_diag_data[workL[tid] + countl] = t;
//                     countl++;
//                 }
//                 else
//                 {
//                     d_data[i] = t;
//                     if (fabs(t) < MAT_TOL)
//                     {
//                         t = 1.0e-6;
//                     }
//                     D_data[i] = 1. / t;
//                 }
//             }
//         }
//     }
//     L_diag_i[n] = L_nnz;
//     U_diag_i[n] = U_nnz;

// /* Sort L_diag_j and U_diag_j using insertion sort */
// #pragma omp parallel for private(i, j, k, temp_idx, temp_data) num_threads(nt) schedule(static)
//     for (i = 0; i < n; i++)
//     {
//         /* Sort L_diag_j and L_diag_data */
//         if (L_diag_i[i + 1] > L_diag_i[i])
//         {
//             JX_Int len = L_diag_i[i + 1] - L_diag_i[i];
//             for (j = L_diag_i[i] + 1; j < L_diag_i[i + 1]; j++)
//             {
//                 temp_idx = L_diag_j[j];
//                 temp_data = L_diag_data[j];
//                 k = j - 1;
//                 while (k >= L_diag_i[i] && L_diag_j[k] > temp_idx)
//                 {
//                     L_diag_j[k + 1] = L_diag_j[k];
//                     L_diag_data[k + 1] = L_diag_data[k];
//                     k--;
//                 }
//                 L_diag_j[k + 1] = temp_idx;
//                 L_diag_data[k + 1] = temp_data;
//             }
//         }
//         /* Sort U_diag_j and U_diag_data */
//         if (U_diag_i[i + 1] > U_diag_i[i])
//         {
//             JX_Int len = U_diag_i[i + 1] - U_diag_i[i];
//             for (j = U_diag_i[i] + 1; j < U_diag_i[i + 1]; j++)
//             {
//                 temp_idx = U_diag_j[j];
//                 temp_data = U_diag_data[j];
//                 k = j - 1;
//                 while (k >= U_diag_i[i] && U_diag_j[k] > temp_idx)
//                 {
//                     U_diag_j[k + 1] = U_diag_j[k];
//                     U_diag_data[k + 1] = U_diag_data[k];
//                     k--;
//                 }
//                 U_diag_j[k + 1] = temp_idx;
//                 U_diag_data[k + 1] = temp_data;
//             }
//         }
//     }

//     memcpy(d1_data, d_data, n * sizeof(JX_Real));
//     // memcpy(L1_diag_data, L_diag_data, L_nnz * sizeof(JX_Real));
//     // memcpy(U1_diag_data, U_diag_data, U_nnz * sizeof(JX_Real));


// for (i = 0; i < n; i++)
//     {
//         for (j = L_diag_i[i]; j < L_diag_i[i + 1]; j++)
//         {
//             temp_data = L_diag_data[j];
//             L_diag_data[j] = D_data[i] * temp_data;
//         }
//     }


//     /* ILU sweeps */
//     for (s = 0; s < sweep; s++)
//     {
// #pragma omp parallel num_threads(nt)
//         {

//             /* Update diagonal d_data */
// #pragma omp for private(i, j, k, l, jj) schedule(static)
//             for (i = 0; i < n; i++)
//             {
//                 d_data[i] = d1_data[i];
//                 for (k = L_diag_i[i]; k < L_diag_i[i + 1]; k++)
//                 {
//                     jj = L_diag_j[k];
//                     for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++)
//                     {
//                         if (U_diag_j[l] == i)
//                         {
//                             d_data[i] -= L_diag_data[k] * U_diag_data[l];
//                         }
//                     }
//                 }
//             }
// #pragma omp barrier

// /* Update D_data */
// #pragma omp for private(i, t) schedule(static)
//             for (i = 0; i < n; i++)
//             {
//                 t = d_data[i];
//                 if (fabs(t) < MAT_TOL)
//                     t = 1.0e-6;
//                 D_data[i] = 1. / t;
//             }


// /* Update U matrix */
// #pragma omp for private(i, j, k, l, jj, col) schedule(static)
//             for (i = 0; i < n; i++)
//             {
//                 for (j = U_diag_i[i]; j < U_diag_i[i + 1]; j++)
//                 {
//                     // U2_diag_data[j] = U1_diag_data[j];
//                     for (k = L_diag_i[i]; k < L_diag_i[i + 1]; k++)
//                     {
//                         jj = L_diag_j[k];
//                         for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++)
//                         {
//                             if (U_diag_j[l] == U_diag_j[j])
//                             {
//                                 U_diag_data[j] -= L_diag_data[k] * U_diag_data[l];
//                             }
//                         }
//                     }
//                 }
//             }
// #pragma omp barrier

// /* Update L matrix */
// #pragma omp for private(i, j, k, l, jj, col) schedule(static)
//             for (i = 0; i < n; i++)
//             {
//                 for (j = L_diag_i[i]; j < L_diag_i[i + 1]; j++)
//                 {
//                     // L2_diag_data[j] = L1_diag_data[j];
//                     col = L_diag_j[j];
//                     for (k = L_diag_i[i]; k < L_diag_i[i + 1]; k++)
//                     {
//                         if (L_diag_j[k] < col)
//                         {
//                             jj = L_diag_j[k];
//                             for (l = U_diag_i[jj]; l < U_diag_i[jj + 1]; l++)
//                             {
//                                 if (U_diag_j[l] == col)
//                                 {
//                                     L_diag_data[j] -= L_diag_data[k] * U_diag_data[l];
//                                 }
//                             }
//                         }
//                     }
//                     L_diag_data[j] *= D_data[col];
//                 }
//             }
//             // memcpy(L_diag_data, L2_diag_data, L_nnz * sizeof(JX_Real));
//             // memcpy(U_diag_data, U2_diag_data, U_nnz * sizeof(JX_Real));

// #pragma omp barrier
//         }
//     }

//     /* Create L matrix */
//     matL = jx_ParCSRMatrixCreate(comm, jx_ParCSRMatrixGlobalNumRows(A),
//                                  jx_ParCSRMatrixGlobalNumRows(A),
//                                  jx_ParCSRMatrixRowStarts(A),
//                                  jx_ParCSRMatrixColStarts(A), 0, L_nnz, 0);
//     L_diag = jx_ParCSRMatrixDiag(matL);
//     jx_CSRMatrixI(L_diag) = L_diag_i;
//     if (L_nnz)
//     {
//         jx_CSRMatrixData(L_diag) = L_diag_data;
//         jx_CSRMatrixJ(L_diag) = L_diag_j;
//     }
//     else
//     {
//         jx_TFree(L_diag_j);
//         jx_TFree(L_diag_data);
//     }
//     local_nnz = (JX_Real)L_nnz;
//     jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
//     jx_ParCSRMatrixDNumNonzeros(matL) = total_nnz;

//     /* Create U matrix */
//     matU = jx_ParCSRMatrixCreate(comm, jx_ParCSRMatrixGlobalNumRows(A),
//                                  jx_ParCSRMatrixGlobalNumRows(A),
//                                  jx_ParCSRMatrixRowStarts(A),
//                                  jx_ParCSRMatrixColStarts(A), 0, U_nnz, 0);
//     U_diag = jx_ParCSRMatrixDiag(matU);
//     jx_CSRMatrixI(U_diag) = U_diag_i;
//     if (U_nnz)
//     {
//         jx_CSRMatrixData(U_diag) = U_diag_data;
//         jx_CSRMatrixJ(U_diag) = U_diag_j;
//     }
//     else
//     {
//         jx_TFree(U_diag_j);
//         jx_TFree(U_diag_data);
//     }
//     local_nnz = (JX_Real)U_nnz;
//     jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
//     jx_ParCSRMatrixDNumNonzeros(matU) = total_nnz;


//     vec_D = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
//                                 jx_ParCSRMatrixGlobalNumRows(A),
//                                 jx_ParCSRMatrixRowStarts(A) );
//     jx_ParVectorInitialize(vec_D);
//     D_local = jx_ParVectorLocalVector(vec_D);
//     D1_data = jx_VectorData(D_local);

//     memcpy(D1_data, D_data, n * sizeof(JX_Real));

//     /* Set output parameters */
//     *Lptr = matL;
//     *Dptr = D_data;
//     *Uptr = matU;
//     *u_end = NULL;
//     *D_array = vec_D;

// //     char FileNameCoaMat[256];
// //     jx_sprintf(FileNameCoaMat, "L_CSR_%d", 2);
// //     jx_ParCSRMatrixPrint(matL, FileNameCoaMat);
// //     jx_sprintf(FileNameCoaMat, "U_CSR_%d", 2);
// //     jx_ParCSRMatrixPrint(matU, FileNameCoaMat);

// //    FILE *fp;
// //    jx_sprintf(FileNameCoaMat, "D_%d", 2);
// //    fp = fopen(FileNameCoaMat, "w");
// //    for(j = 0; j < n; j++){
// //    jx_fprintf(fp, "%.14e\n", D_data[j]);
// //    }
// //    fclose(fp);


//     /* Free temporary memory */
//     jx_TFree(workL);
//     jx_TFree(workU);
//     jx_TFree(d_data);
//     jx_TFree(d1_data);
//     jx_TFree(L1_diag_data);
//     jx_TFree(U1_diag_data);

//     return jx_error_flag;
// }




void jx_CSRMatrixTopologicSortILU(jx_CSRMatrix *L, jx_CSRMatrix *U,
                                  JX_Int *nlevL, JX_Int **jlevL, JX_Int **ilevL,
                                  JX_Int *nlevU, JX_Int **jlevU, JX_Int **ilevU)
{
    JX_Int *L_I = jx_CSRMatrixI(L);
    JX_Int *L_J = jx_CSRMatrixJ(L);
    JX_Int *U_I = jx_CSRMatrixI(U);
    JX_Int *U_J = jx_CSRMatrixJ(U);
    JX_Int n = jx_CSRMatrixNumRows(L);

    // 检查矩阵行数一致性
    if (jx_CSRMatrixNumRows(L) != jx_CSRMatrixNumRows(U)) {
        *jlevL = *ilevL = *jlevU = *ilevU = NULL;
        *nlevL = *nlevU = 0;
        return;
    }
    // 分配内存
    JX_Int *level = (JX_Int *)calloc(n, sizeof(JX_Int));
    *jlevL = (JX_Int *)calloc(n, sizeof(JX_Int));
    *ilevL = (JX_Int *)calloc(n + 1, sizeof(JX_Int));
    *jlevU = (JX_Int *)calloc(n, sizeof(JX_Int));
    *ilevU = (JX_Int *)calloc(n + 1, sizeof(JX_Int));

    // 检查内存分配
    if (!level || !(*jlevL) || !(*ilevL) || !(*jlevU) || !(*ilevU)) {
        free(level);
        free(*jlevL); free(*ilevL); free(*jlevU); free(*ilevU);
        *jlevL = *ilevL = *jlevU = *ilevU = NULL;
        *nlevL = *nlevU = 0;
        return;
    }

    JX_Int i, j, k, l;
    JX_Int local_nlevL = 0, local_nlevU = 0;

    // for (i = 0; i <= n; i++) printf("%d ", L_I[i]);
    // printf("\n");
    // for (i = 0; i < L_I[n]; i++) printf("%d ", L_J[i]);
    // printf("\n");

    // for (i = 0; i <= n; i++) printf("%d ", U_I[i]);
    // printf("\n");
    // for (i = 0; i < U_I[n]; i++) printf("%d ", U_J[i]);
    // printf("\n");

    for(i=0; i<n; i++) level[i] = 0;

    // 初始化 ilevL
    for (i = 0; i <= n; i++) (*ilevL)[i] = 0;
    for (i = 0; i <= n; i++) (*ilevU)[i] = 0;
    for (i = 0; i < n; i++) (*jlevU)[i] = 0;
    for (i = 0; i < n; i++) (*jlevL)[i] = 0;

    // ---------- Step 1: 构造下三角矩阵 L 的层次 ----------
    for (i = 0; i < n; i++) {
        l = 0;
        for (j = L_I[i]; j < L_I[i + 1]; j++) {
            if (L_J[j] < i) {
                l = (l > level[L_J[j]]) ? l : level[L_J[j]];
            }
        }
        level[i] = l + 1;
        (*ilevL)[l + 1]++;
        //printf("%d",l + 1);
        local_nlevL = (local_nlevL > (l + 1)) ? local_nlevL : (l + 1);
    }
    //printf("\n");

    for (i = 1; i <= local_nlevL; i++) (*ilevL)[i] += (*ilevL)[i - 1];

    for (i = 0; i < n; i++) {
        k = (*ilevL)[level[i] - 1];
        (*jlevL)[k] = i;
        (*ilevL)[level[i] - 1]++;
    }

    for (i = local_nlevL - 1; i > 0; i--) (*ilevL)[i] = (*ilevL)[i - 1];
    (*ilevL)[0] = 0;

    *nlevL = local_nlevL + 1; // 保持原始代码的 +1 逻辑

    // printf("Lower Triangular Matrix L:\n");
    // printf("Number of levels (nlevL): %d\n", *nlevL);
    // printf("jlevL (row indices per level): ");
    // for (i = 0; i < n; i++) printf("%d ", (*jlevL)[i]);
    // printf("\n");
    // printf("ilevL (level offsets): ");
    // for (i = 0; i <= local_nlevL; i++) printf("%d ", (*ilevL)[i]);
    // printf("\n\n");

    // ---------- Step 2: 构造上三角矩阵 U 的层次 ----------
    for (i = 0; i < n; i++) level[i] = 0; // 重新清零 level
    for (i = 0; i <= n; i++) (*ilevU)[i] = 0; // 初始化 ilevU

    for (i = n - 1; i >= 0; i--) {
        l = 0;
        for (j = U_I[i]; j < U_I[i + 1]; j++) {
            if (U_J[j] > i) {
                l = (l > level[U_J[j]]) ? l : level[U_J[j]];
            }
        }
        level[i] = l + 1;
        (*ilevU)[l + 1]++;
        //printf("%d",l + 1);
        local_nlevU = (local_nlevU > (l + 1)) ? local_nlevU : (l + 1);
    }
    //printf("\n");
    for (i = 1; i <= local_nlevU; i++) (*ilevU)[i] += (*ilevU)[i - 1];

    for (i = n - 1; i >= 0; i--) {
        k = (*ilevU)[level[i] - 1];
        (*jlevU)[k] = i;
        (*ilevU)[level[i] - 1]++;
    }

    for (i = local_nlevU - 1; i > 0; i--) (*ilevU)[i] = (*ilevU)[i - 1];
    (*ilevU)[0] = 0;

    *nlevU = local_nlevU + 1;

   //  printf("Upper Triangular Matrix U:\n");
   //  printf("Number of levels (nlevU): %d\n", *nlevU);
   //  printf("jlevU (row indices per level): ");
   //  for (i = 0; i < n; i++) printf("%d ", (*jlevU)[i]);
   //  printf("\n");
   //  printf("ilevU (level offsets): ");
   //  for (i = 0; i <= local_nlevU; i++) printf("%d ", (*ilevU)[i]);
   //  printf("\n");

    free(level);
}

void jx_CSRMatrixTopologicSortILU1(jx_CSRMatrix *L, jx_CSRMatrix *U,
                                   JX_Int *nlevL, JX_Int **jlevL, JX_Int **ilevL, JX_Int **permL, JX_Int **inv_permL,
                                   JX_Int *nlevU, JX_Int **jlevU, JX_Int **ilevU, JX_Int **permU, JX_Int **inv_permU)
{
    JX_Int *L_I = jx_CSRMatrixI(L);
    JX_Int *L_J = jx_CSRMatrixJ(L);
    JX_Real *L_data = jx_CSRMatrixData(L);
    JX_Int *U_I = jx_CSRMatrixI(U);
    JX_Int *U_J = jx_CSRMatrixJ(U);
    JX_Real *U_data = jx_CSRMatrixData(U);
    JX_Int n = jx_CSRMatrixNumRows(L);

    // 检查矩阵行数一致性
    if (jx_CSRMatrixNumRows(L) != jx_CSRMatrixNumRows(U))
    {
        *jlevL = *ilevL = *jlevU = *ilevU = NULL;
        *nlevL = *nlevU = 0;
        return;
    }
    // 分配内存
    JX_Int *level = (JX_Int *)calloc(n, sizeof(JX_Int));
    *jlevL = (JX_Int *)calloc(n, sizeof(JX_Int));
    *ilevL = (JX_Int *)calloc(n + 1, sizeof(JX_Int));
    *jlevU = (JX_Int *)calloc(n, sizeof(JX_Int));
    *ilevU = (JX_Int *)calloc(n + 1, sizeof(JX_Int));

    JX_Int i, j, k, l;
    JX_Int local_nlevL = 0, local_nlevU = 0;

    // for (i = 0; i <= n; i++) printf("%d ", L_I[i]);
    // printf("\n");
    // for (i = 0; i < L_I[n]; i++) printf("%d ", L_J[i]);
    // printf("\n");

    // for (i = 0; i <= n; i++) printf("%d ", U_I[i]);
    // printf("\n");
    // for (i = 0; i < U_I[n]; i++) printf("%d ", U_J[i]);
    // printf("\n");

    for (i = 0; i < n; i++)
        level[i] = 0;

    // 初始化 ilevL
    for (i = 0; i <= n; i++)
        (*ilevL)[i] = 0;
    for (i = 0; i <= n; i++)
        (*ilevU)[i] = 0;
    for (i = 0; i < n; i++)
        (*jlevU)[i] = 0;
    for (i = 0; i < n; i++)
        (*jlevL)[i] = 0;

    // ---------- Step 1: 构造下三角矩阵 L 的层次 ----------
    for (i = 0; i < n; i++)
    {
        l = 0;
        for (j = L_I[i]; j < L_I[i + 1]; j++)
        {
            if (L_J[j] < i)
            {
                l = (l > level[L_J[j]]) ? l : level[L_J[j]];
            }
        }
        level[i] = l + 1;
        (*ilevL)[l + 1]++;
        // printf("%d",l + 1);
        local_nlevL = (local_nlevL > (l + 1)) ? local_nlevL : (l + 1);
    }
    // printf("\n");

    for (i = 1; i <= local_nlevL; i++)
        (*ilevL)[i] += (*ilevL)[i - 1];

    for (i = 0; i < n; i++)
    {
        k = (*ilevL)[level[i] - 1];
        (*jlevL)[k] = i;
        (*ilevL)[level[i] - 1]++;
    }

    for (i = local_nlevL - 1; i > 0; i--)
        (*ilevL)[i] = (*ilevL)[i - 1];
    (*ilevL)[0] = 0;

    *nlevL = local_nlevL + 1; // 保持原始代码的 +1 逻辑

    // printf("Lower Triangular Matrix L:\n");
    // printf("Number of levels (nlevL): %d\n", *nlevL);
    // printf("jlevL (row indices per level): ");
    // for (i = 0; i < n; i++) printf("%d ", (*jlevL)[i]);
    // printf("\n");
    // printf("ilevL (level offsets): ");
    // for (i = 0; i <= local_nlevL; i++) printf("%d ", (*ilevL)[i]);
    // printf("\n\n");

    // ---------- Step 2: 构造上三角矩阵 U 的层次 ----------
    for (i = 0; i < n; i++)
        level[i] = 0; // 重新清零 level
    for (i = 0; i <= n; i++)
        (*ilevU)[i] = 0; // 初始化 ilevU

    for (i = n - 1; i >= 0; i--)
    {
        l = 0;
        for (j = U_I[i]; j < U_I[i + 1]; j++)
        {
            if (U_J[j] > i)
            {
                l = (l > level[U_J[j]]) ? l : level[U_J[j]];
            }
        }
        level[i] = l + 1; // 最大层+1
        (*ilevU)[l + 1]++;
        // printf("%d",l + 1);
        local_nlevU = (local_nlevU > (l + 1)) ? local_nlevU : (l + 1);
    }
    // printf("\n");
    for (i = 1; i <= local_nlevU; i++)
        (*ilevU)[i] += (*ilevU)[i - 1];

    for (i = n - 1; i >= 0; i--)
    {
        k = (*ilevU)[level[i] - 1];
        (*jlevU)[k] = i;
        (*ilevU)[level[i] - 1]++;
    }

    for (i = local_nlevU - 1; i > 0; i--)
        (*ilevU)[i] = (*ilevU)[i - 1];
    (*ilevU)[0] = 0;

    *nlevU = local_nlevU + 1;

    //  printf("Upper Triangular Matrix U:\n");
    //  printf("Number of levels (nlevU): %d\n", *nlevU);
    //  printf("jlevU (row indices per level): ");
    //  for (i = 0; i < n; i++) printf("%d ", (*jlevU)[i]);
    //  printf("\n");
    //  printf("ilevU (level offsets): ");
    //  for (i = 0; i <= local_nlevU; i++) printf("%d ", (*ilevU)[i]);
    //  printf("\n");

    // ---------- Step 3: 根据 jlevL 构造 permL / inv_permL ----------
    JX_Int *permL_local = (JX_Int *)malloc(n * sizeof(JX_Int));
    JX_Int *inv_permL_local = (JX_Int *)malloc(n * sizeof(JX_Int));

    for (JX_Int new_i = 0; new_i < n; new_i++)
    {
        JX_Int old_i = (*jlevL)[new_i]; // jlevL already holds old row indices in level order
        permL_local[old_i] = new_i;     // old -> new
        inv_permL_local[new_i] = old_i; // new -> old
    }

    // ---------- Step 4: 重排 L（只重排行） ----------
    JX_Int *row_nnz_L = (JX_Int *)calloc(n, sizeof(JX_Int));

    for (JX_Int ii = 0; ii < n; ii++)
    {
        JX_Int old_i = inv_permL_local[ii];
        row_nnz_L[ii] = L_I[old_i + 1] - L_I[old_i];
    }

    JX_Int *new_L_I = (JX_Int *)malloc((n + 1) * sizeof(JX_Int));

    new_L_I[0] = 0;
    for (JX_Int ii = 1; ii <= n; ii++)
        new_L_I[ii] = new_L_I[ii - 1] + row_nnz_L[ii - 1];

    JX_Int nnzL = new_L_I[n];
    JX_Int *new_L_J = (JX_Int *)malloc(nnzL * sizeof(JX_Int));
    JX_Real *new_L_data = (JX_Real *)malloc(nnzL * sizeof(JX_Real));
    JX_Int *posL = (JX_Int *)calloc(n, sizeof(JX_Int));

    for (JX_Int ii = 0; ii < n; ii++)
    {
        JX_Int old_i = inv_permL_local[ii];
        for (JX_Int jj = L_I[old_i]; jj < L_I[old_i + 1]; jj++)
        {
            JX_Int insert_pos = new_L_I[ii] + posL[ii];
            new_L_J[insert_pos] = L_J[jj]; // 列保持旧编号
            new_L_data[insert_pos] = L_data[jj];
            posL[ii]++;
        }
    }

    // 替换 L 的 CSR 指针（注意：请确认你的 API 是否允许直接赋值）
    free(L_I);
    free(L_J);
    free(L_data);
    jx_CSRMatrixI(L) = new_L_I;
    jx_CSRMatrixJ(L) = new_L_J;
    jx_CSRMatrixData(L) = new_L_data;

    // ---------- 输出 permL / inv_permL ----------
    *permL = permL_local;
    *inv_permL = inv_permL_local;

    // 清理 L 临时内存
    free(row_nnz_L);
    free(posL);

    // ---------- 对 U 做同样的处理：构造 permU/inv_permU 并重排 U 行 ----------
    JX_Int *permU_local = (JX_Int *)malloc(n * sizeof(JX_Int));
    JX_Int *inv_permU_local = (JX_Int *)malloc(n * sizeof(JX_Int));

    for (JX_Int new_i = 0; new_i < n; new_i++)
    {
        JX_Int old_i = (*jlevU)[new_i];
        permU_local[old_i] = new_i;
        inv_permU_local[new_i] = old_i;
    }

    JX_Int *row_nnz_U = (JX_Int *)calloc(n, sizeof(JX_Int));
    for (JX_Int ii = 0; ii < n; ii++)
    {
        JX_Int old_i = inv_permU_local[ii];
        row_nnz_U[ii] = U_I[old_i + 1] - U_I[old_i];
    }

    JX_Int *new_U_I = (JX_Int *)malloc((n + 1) * sizeof(JX_Int));

    new_U_I[0] = 0;
    for (JX_Int ii = 1; ii <= n; ii++)
        new_U_I[ii] = new_U_I[ii - 1] + row_nnz_U[ii - 1];

    JX_Int nnzU = new_U_I[n];
    JX_Int *new_U_J = (JX_Int *)malloc(nnzU * sizeof(JX_Int));
    JX_Real *new_U_data = (JX_Real *)malloc(nnzU * sizeof(JX_Real));
    JX_Int *posU = (JX_Int *)calloc(n, sizeof(JX_Int));

    for (JX_Int ii = 0; ii < n; ii++)
    {
        JX_Int old_i = inv_permU_local[ii];
        for (JX_Int jj = U_I[old_i]; jj < U_I[old_i + 1]; jj++)
        {
            JX_Int insert_pos = new_U_I[ii] + posU[ii];
            new_U_J[insert_pos] = U_J[jj]; // 列保持旧编号
            new_U_data[insert_pos] = U_data[jj];
            posU[ii]++;
        }
    }

    // 替换 U 的 CSR 指针
    free(U_I);
    free(U_J);
    free(U_data);
    jx_CSRMatrixI(U) = new_U_I;
    jx_CSRMatrixJ(U) = new_U_J;
    jx_CSRMatrixData(U) = new_U_data;

    // 输出 permU / inv_permU
    *permU = permU_local;
    *inv_permU = inv_permU_local;

    // cleanup
    free(row_nnz_U);
    free(posU);

    free(level);
}

// JX_Int
// jx_GreedyColoring(jx_ParCSRMatrix *A,
//                   JX_Int          nLU,
//                   JX_Int         **row_by_color_out,
//                   JX_Int         **color_starts_out,
//                   JX_Int          *num_colors_out)
// {
//     jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//     JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//     JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);

//     JX_Int i, jj, c, neighbor;

//     JX_Int *color = (JX_Int *)calloc(nLU, sizeof(JX_Int));
//     for (i = 0; i < nLU; i++) color[i] = -1;

//     JX_Int used_colors_size = 16;
//     char *used_colors = (char *)calloc(used_colors_size, sizeof(char));

//     JX_Int *color_counts = (JX_Int *)calloc(nLU + 1, sizeof(JX_Int));

//     JX_Int num_colors = 0;
//     for (i = 0; i < nLU; i++) {
//         if (num_colors > 0) memset(used_colors, 0, num_colors * sizeof(char));

//         for (jj = A_diag_i[i]; jj < A_diag_i[i + 1]; jj++) {
//             neighbor = A_diag_j[jj];
//             if (color[neighbor] >= 0)
//                 used_colors[color[neighbor]] = 1;
//         }

//         c = 0;
//         while (c < num_colors && used_colors[c] == 1) c++;

//         if (c >= num_colors) {
//             if (num_colors >= used_colors_size) {
//                 used_colors_size *= 2;
//                 char *new_used_colors = (char *)realloc(used_colors, used_colors_size * sizeof(char));
//                 if (!new_used_colors) {
//                     fprintf(stderr, "Memory reallocation failed!\n");
//                     exit(1);
//                 }
//                 used_colors = new_used_colors;
//                 memset(used_colors + num_colors, 0, (used_colors_size - num_colors) * sizeof(char));
//             }
//             num_colors++;
//         }

//         color[i] = c;
//         color_counts[c]++;
//     }

//     JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *color_starts = (JX_Int *)malloc((num_colors + 1) * sizeof(JX_Int));

//     color_starts[0] = 0;
//     for (c = 0; c < num_colors; c++) {
//         color_starts[c + 1] = color_starts[c] + color_counts[c];
//     }

//     // 用 color_pos 作为写位置指针，避免破坏 color_counts 和 color_starts
//     JX_Int *color_pos = (JX_Int *)malloc(num_colors * sizeof(JX_Int));
//     memcpy(color_pos, color_starts, num_colors * sizeof(JX_Int));

//     for (i = 0; i < nLU; i++) {
//         row_by_color[color_pos[color[i]]++] = i;
//     }

//     *row_by_color_out = row_by_color;
//     *color_starts_out = color_starts;
//     *num_colors_out = num_colors;

//     free(color);
//     free(used_colors);
//     free(color_counts);
//     free(color_pos);

//     printf("Number of levels : %d\n", *num_colors_out);

//     return 0;
// }

// 7.28
JX_Int
jx_GreedyColoring_L(jx_ParCSRMatrix *L,
                    JX_Int nLU,
                    JX_Int **row_by_color_out,
                    JX_Int **color_starts_out,
                    JX_Int *num_colors_out)
{
    jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
    JX_Int *L_i = jx_CSRMatrixI(L_diag);
    JX_Int *L_j = jx_CSRMatrixJ(L_diag);

    JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int used_colors_size = 16;
    char *used = (char *)calloc(used_colors_size, sizeof(char));

    for (JX_Int i = 0; i < nLU; i++)
        color[i] = -1;

    JX_Int max_color = -1;

    for (JX_Int i = 0; i < nLU; i++)
    {
        // 标记当前行依赖的颜色
        if (max_color >= 0)
            memset(used, 0, (max_color + 1) * sizeof(char));

        for (JX_Int jj = L_i[i]; jj < L_i[i + 1]; jj++)
        {
            JX_Int col = L_j[jj];
            if (col < i && color[col] >= 0)
            {
                used[color[col]] = 1;
            }
        }

        // 选一个未使用的最小颜色
        JX_Int c = 0;
        while (c < used_colors_size && used[c])
            c++;
        if (c >= used_colors_size)
        {
            used_colors_size *= 2;
            char *new_used = (char *)realloc(used, used_colors_size * sizeof(char));
            if (!new_used)
            {
                fprintf(stderr, "Memory reallocation failed!\n");
                free(color);
                free(used);
                exit(1);
            }
            used = new_used;
            memset(used + c, 0, (used_colors_size - c) * sizeof(char));
        }
        color[i] = c;
        if (c > max_color)
            max_color = c;

        // 清除标记
        for (JX_Int jj = L_i[i]; jj < L_i[i + 1]; jj++)
        {
            JX_Int col = L_j[jj];
            if (col < i && color[col] >= 0)
            {
                used[color[col]] = 0;
            }
        }
    }

    free(used);
    *num_colors_out = max_color + 1;

    // 统计每个颜色的数量
    JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
    for (JX_Int i = 0; i < nLU; i++)
        color_count[color[i]]++;

    // 构造 color_starts 数组
    JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
    color_starts[0] = 0;
    for (JX_Int c = 1; c <= *num_colors_out; c++)
        color_starts[c] = color_starts[c - 1] + color_count[c - 1];

    // 构造 row_by_color 数组
    JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
    memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

    for (JX_Int i = 0; i < nLU; i++)
    {
        JX_Int c = color[i];
        row_by_color[temp_index[c]++] = i;
    }

    // 输出结果
    *row_by_color_out = row_by_color;
    *color_starts_out = color_starts;

    //  printf("Number of levels : %d\n", *num_colors_out);
    //  printf("jlevU (row indices per level): ");
    //  for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*row_by_color_out)[i]);
    //  printf("\n");
    //  printf("ilevU (level offsets): ");
    //  for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", (*color_starts_out)[i]);
    //  printf("\n");
    // 清理
    free(color_count);
    free(temp_index);
    free(color);

    return 0;
}

JX_Int jx_GreedyColoring_U(jx_ParCSRMatrix *U,
                           JX_Int nLU,
                           JX_Int **row_by_color_out,
                           JX_Int **color_starts_out,
                           JX_Int *num_colors_out)
{
    jx_CSRMatrix *U_diag = jx_ParCSRMatrixDiag(U);
    JX_Int *U_i = jx_CSRMatrixI(U_diag);
    JX_Int *U_j = jx_CSRMatrixJ(U_diag);

    JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int used_colors_size = 16;
    char *used = (char *)calloc(used_colors_size, sizeof(char));

    for (JX_Int i = 0; i < nLU; i++)
        color[i] = -1;

    JX_Int max_color = -1;

    // 从最后一行开始染色，让最后一行最先染、染成颜色0
    for (JX_Int i = nLU - 1; i >= 0; i--)
    {
        if (max_color >= 0)
            memset(used, 0, (max_color + 1) * sizeof(char));

        // 当前行依赖于行号更小的行（下三角）
        for (JX_Int jj = U_i[i]; jj < U_i[i + 1]; jj++)
        {
            JX_Int col = U_j[jj];
            if (col > i && color[col] >= 0)
            {
                used[color[col]] = 1;
            }
        }

        // 选择未用的最小颜色
        JX_Int c = 0;
        while (c < used_colors_size && used[c])
            c++;
        if (c >= used_colors_size)
        {
            used_colors_size *= 2;
            char *new_used = (char *)realloc(used, used_colors_size * sizeof(char));
            if (!new_used)
            {
                fprintf(stderr, "Memory reallocation failed!\n");
                free(color);
                free(used);
                exit(1);
            }
            used = new_used;
            memset(used + c, 0, (used_colors_size - c) * sizeof(char));
        }

        color[i] = c;
        if (c > max_color)
            max_color = c;

        // 清除标记
        for (JX_Int jj = U_i[i]; jj < U_i[i + 1]; jj++)
        {
            JX_Int col = U_j[jj];
            if (col < i && color[col] >= 0)
            {
                used[color[col]] = 0;
            }
        }
    }

    free(used);
    *num_colors_out = max_color + 1;

    // 统计每个颜色的数量
    JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
    for (JX_Int i = 0; i < nLU; i++)
        color_count[color[i]]++;

    // 构造 color_starts 数组
    JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
    color_starts[0] = 0;
    for (JX_Int c = 1; c <= *num_colors_out; c++)
        color_starts[c] = color_starts[c - 1] + color_count[c - 1];

    // 构造 row_by_color 数组，并保证每个颜色的行是按从大到小顺序排列（倒着写入）
    JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
    memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

    for (JX_Int i = nLU - 1; i >= 0; i--)
    {
        JX_Int c = color[i];
        row_by_color[temp_index[c]++] = i;
    }

    // 输出结果
    *row_by_color_out = row_by_color;
    *color_starts_out = color_starts;

    // 打印调试信息
    //  printf("Number of levels : %d\n", *num_colors_out);
    //  printf("jlevU (row indices per level): ");
    //  for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*row_by_color_out)[i]);
    //  printf("\n");
    //  printf("ilevU (level offsets): ");
    //  for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", (*color_starts_out)[i]);
    //  printf("\n");

    // 清理
    free(color_count);
    free(temp_index);
    free(color);

    return 0;
}

// JX_Int
// jx_GreedyColoring_L1(jx_ParCSRMatrix *L,
//                   JX_Int           nLU,
//                   JX_Int         **row_by_color_out,
//                   JX_Int         **color_starts_out,
//                   JX_Int          *num_colors_out,
//                   JX_Int         **perm_out,
//                   JX_Int         **inv_perm_out)
// {
//     jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
//     JX_Int *L_i = jx_CSRMatrixI(L_diag);
//     JX_Int *L_j = jx_CSRMatrixJ(L_diag);
//     JX_Real *L_data = jx_CSRMatrixData(L_diag);

//     JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int used_colors_size = 16;
//     char *used = (char *)calloc(used_colors_size, sizeof(char));

//     for (JX_Int i = 0; i < nLU; i++) color[i] = -1;

//     JX_Int max_color = -1;

//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         // 标记当前行依赖的颜色
//         if (max_color >= 0) memset(used, 0, (max_color + 1) * sizeof(char));

//         for (JX_Int jj = L_i[i]; jj < L_i[i+1]; jj++)
//         {
//             JX_Int col = L_j[jj];
//             if (col < i && color[col] >= 0)
//             {
//                 used[color[col]] = 1;
//             }
//         }

//         // 选一个未使用的最小颜色
//         JX_Int c = 0;
//         while (c < used_colors_size && used[c]) c++;
//         if (c >= used_colors_size) {
//             used_colors_size *= 2;
//             char *new_used = (char *)realloc(used, used_colors_size * sizeof(char));
//             if (!new_used) {
//                 fprintf(stderr, "Memory reallocation failed!\n");
//                 free(color);
//                 free(used);
//                 exit(1);
//             }
//             used = new_used;
//             memset(used + c, 0, (used_colors_size - c) * sizeof(char));
//         }
//         color[i] = c;
//         if (c > max_color) max_color = c;

//         // 清除标记
//         for (JX_Int jj = L_i[i]; jj < L_i[i+1]; jj++)
//         {
//             JX_Int col = L_j[jj];
//             if (col < i && color[col] >= 0)
//             {
//                 used[color[col]] = 0;
//             }
//         }
//     }

//     free(used);
//     *num_colors_out = max_color + 1;

//     // 统计每个颜色的数量
//     JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++)
//         color_count[color[i]]++;

//     // 构造 color_starts 数组
//     JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
//     color_starts[0] = 0;
//     for (JX_Int c = 1; c <= *num_colors_out; c++)
//         color_starts[c] = color_starts[c - 1] + color_count[c - 1];

//     // 构造 row_by_color 数组
//     JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
//     memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         JX_Int c = color[i];
//         row_by_color[temp_index[c]++] = i;
//     }

//     // === 构造 perm / inv_perm ===
//     JX_Int *perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *inv_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     for (JX_Int new_i = 0; new_i < nLU; new_i++) {
//         JX_Int old_i = row_by_color[new_i];
//         perm[old_i] = new_i;
//         inv_perm[new_i] = old_i;
//     }

//     // === 重排 L_diag 到新顺序 ===
//     JX_Int *new_i = (JX_Int *)malloc((nLU + 1) * sizeof(JX_Int));
//     JX_Int *row_nnz = (JX_Int *)calloc(nLU, sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int old_i = inv_perm[i];
//         row_nnz[i] = L_i[old_i + 1] - L_i[old_i];
//     }

//     new_i[0] = 0;
//     for (JX_Int i = 1; i <= nLU; i++)
//         new_i[i] = new_i[i - 1] + row_nnz[i - 1];

//     JX_Int nnz = new_i[nLU];
//     JX_Int *new_j = (JX_Int *)malloc(nnz * sizeof(JX_Int));
//     JX_Real *new_data = (JX_Real *)malloc(nnz * sizeof(JX_Real));
//     JX_Int *pos = (JX_Int *)calloc(nLU, sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int old_i = inv_perm[i];
//         JX_Int row_start = L_i[old_i];
//         for (JX_Int jj = L_i[old_i]; jj < L_i[old_i + 1]; jj++) {
//             JX_Int insert_pos = new_i[i] + pos[i];
//             new_j[insert_pos] = L_j[jj];
//             new_data[insert_pos] = L_data[jj];
//             pos[i]++;
//         }
//     }

//     // 替换原有 L_diag 内容
//     free(L_i);
//     free(L_j);
//     free(L_data);

//    jx_CSRMatrixData(L_diag ) = new_data;
//    jx_CSRMatrixI(L_diag ) = new_i;
//    jx_CSRMatrixJ(L_diag ) = new_j;

//    // === 生成 jlevL_perm（即 perm[row_by_color]） ===
//     JX_Int *row_by_color_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         row_by_color_perm[i] = perm[row_by_color[i]];
//     }

//     // 输出结果
//     *row_by_color_out = row_by_color_perm;
//     *color_starts_out = color_starts;
//     *perm_out = perm;
//     *inv_perm_out = inv_perm;

//      for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*perm_out)[i]);
//     printf("\n");
//     printf("inv_perm_out: ");
//     for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*inv_perm_out)[i]);
//     printf("\n");

//     printf("Number of levels : %d\n", *num_colors_out);
//     printf("jlevU (row indices per level): ");
//     for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*row_by_color_out)[i]);
//     printf("\n");
//     printf("ilevU (level offsets): ");
//     for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", (*color_starts_out)[i]);
//     printf("\n");

//     // 清理
//     free(color_count);
//     free(temp_index);
//     free(color);
//    free(row_nnz);
//     free(pos);

//     return 0;
// }

JX_Int
jx_GreedyColoring_L1(jx_ParCSRMatrix *L,
                     JX_Int nLU,
                     JX_Int **row_by_color_out, // 按颜色分组的行号（旧编号）
                     JX_Int **color_starts_out, // 每个颜色块的起始位置
                     JX_Int *num_colors_out,    // 颜色数
                     JX_Int **perm_out,         // old → new 行编号
                     JX_Int **inv_perm_out)     // new → old 行编号
{
    jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
    JX_Int *L_i = jx_CSRMatrixI(L_diag);
    JX_Int *L_j = jx_CSRMatrixJ(L_diag);
    JX_Real *L_data = jx_CSRMatrixData(L_diag);

    // === Step 1: greedy coloring ===
    JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int used_colors_size = 16;
    char *used = (char *)calloc(used_colors_size, sizeof(char));

    for (JX_Int i = 0; i < nLU; i++)
        color[i] = -1;
    JX_Int max_color = -1;

    for (JX_Int i = 0; i < nLU; i++)
    {
        // reset used[] for current row
        if (max_color >= 0)
            memset(used, 0, (max_color + 1) * sizeof(char));

        // 标记依赖的已用颜色 (只看下三角 col<i)
        for (JX_Int jj = L_i[i]; jj < L_i[i + 1]; jj++)
        {
            JX_Int col = L_j[jj];
            if (col < i && color[col] >= 0)
                used[color[col]] = 1;
        }

        // 选最小未使用颜色
        JX_Int c = 0;
        while (c < used_colors_size && used[c])
            c++;
        if (c >= used_colors_size)
        {
            used_colors_size *= 2;
            used = (char *)realloc(used, used_colors_size * sizeof(char));
            memset(used + c, 0, (used_colors_size - c) * sizeof(char));
        }
        color[i] = c;
        if (c > max_color)
            max_color = c;
    }

    free(used);
    *num_colors_out = max_color + 1;

    // === Step 2: 构造 row_by_color / color_starts ===
    JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
    for (JX_Int i = 0; i < nLU; i++)
        color_count[color[i]]++;

    JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
    color_starts[0] = 0;
    for (JX_Int c = 1; c <= *num_colors_out; c++)
        color_starts[c] = color_starts[c - 1] + color_count[c - 1];

    JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
    memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

    for (JX_Int i = 0; i < nLU; i++)
    {
        JX_Int c = color[i];
        row_by_color[temp_index[c]++] = i; // 保存的是旧行号
    }

    // === Step 3: 构造 perm / inv_perm ===
    JX_Int *perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *inv_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    for (JX_Int new_i = 0; new_i < nLU; new_i++)
    {
        JX_Int old_i = row_by_color[new_i];
        perm[old_i] = new_i;
        inv_perm[new_i] = old_i;
    }

    // === Step 4: 按 new 行顺序重排 L (只重排行，不重排列) ===
    JX_Int *row_nnz = (JX_Int *)calloc(nLU, sizeof(JX_Int));
    for (JX_Int i = 0; i < nLU; i++)
    {
        JX_Int old_i = inv_perm[i];
        row_nnz[i] = L_i[old_i + 1] - L_i[old_i];
    }

    JX_Int *new_i = (JX_Int *)malloc((nLU + 1) * sizeof(JX_Int));
    new_i[0] = 0;
    for (JX_Int i = 1; i <= nLU; i++)
        new_i[i] = new_i[i - 1] + row_nnz[i - 1];

    JX_Int nnz = new_i[nLU];
    JX_Int *new_j = (JX_Int *)malloc(nnz * sizeof(JX_Int));
    JX_Real *new_data = (JX_Real *)malloc(nnz * sizeof(JX_Real));
    JX_Int *pos = (JX_Int *)calloc(nLU, sizeof(JX_Int));

    for (JX_Int i = 0; i < nLU; i++)
    {
        JX_Int old_i = inv_perm[i];
        for (JX_Int jj = L_i[old_i]; jj < L_i[old_i + 1]; jj++)
        {
            JX_Int insert_pos = new_i[i] + pos[i];
            new_j[insert_pos] = L_j[jj]; // 注意：列号保持旧编号！
            new_data[insert_pos] = L_data[jj];
            pos[i]++;
        }
    }

    // 替换 L_diag 内容（这里假设 L_diag 拥有数据内存）
    free(L_i);
    free(L_j);
    free(L_data);
    jx_CSRMatrixData(L_diag) = new_data;
    jx_CSRMatrixI(L_diag) = new_i;
    jx_CSRMatrixJ(L_diag) = new_j;

    // === 输出结果 ===
    *row_by_color_out = row_by_color; // 旧行号，按颜色分组顺序
    *color_starts_out = color_starts; // 每个颜色块的起始偏移
    *perm_out = perm;                 // old → new
    *inv_perm_out = inv_perm;         // new → old

    // // === Debug 打印 ===
    // printf("perm (old->new): ");
    // for (JX_Int i = 0; i < nLU; i++) printf("%d ", perm[i]);
    // printf("\n");

    // printf("inv_perm (new->old): ");
    // for (JX_Int i = 0; i < nLU; i++) printf("%d ", inv_perm[i]);
    // printf("\n");

    // printf("Number of colors: %d\n", *num_colors_out);
    // printf("row_by_color (old row indices per color): ");
    // for (JX_Int i = 0; i < nLU; i++) printf("%d ", row_by_color[i]);
    // printf("\n");

    // printf("color_starts (offsets): ");
    // for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", color_starts[i]);
    // printf("\n");

    // 清理
    free(color_count);
    free(temp_index);
    free(color);
    free(row_nnz);
    free(pos);

    return 0;
}

JX_Int jx_GreedyColoring_U1(jx_ParCSRMatrix *U,
                            JX_Int nLU,
                            JX_Int **row_by_color_out,
                            JX_Int **color_starts_out,
                            JX_Int *num_colors_out,
                            JX_Int **perm_out,
                            JX_Int **inv_perm_out)
{
    jx_CSRMatrix *U_diag = jx_ParCSRMatrixDiag(U);
    JX_Int *U_i = jx_CSRMatrixI(U_diag);
    JX_Int *U_j = jx_CSRMatrixJ(U_diag);
    JX_Real *U_data = jx_CSRMatrixData(U_diag);

    JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int used_colors_size = 16;
    char *used = (char *)calloc(used_colors_size, sizeof(char));

    for (JX_Int i = 0; i < nLU; i++)
        color[i] = -1;

    JX_Int max_color = -1;

    // 从最后一行开始染色，让最后一行最先染、染成颜色0
    for (JX_Int i = nLU - 1; i >= 0; i--)
    {
        if (max_color >= 0)
            memset(used, 0, (max_color + 1) * sizeof(char));

        // 当前行依赖于行号更小的行（下三角）
        for (JX_Int jj = U_i[i]; jj < U_i[i + 1]; jj++)
        {
            JX_Int col = U_j[jj];
            if (col > i && color[col] >= 0)
            {
                used[color[col]] = 1;
            }
        }

        // 选择未用的最小颜色
        JX_Int c = 0;
        while (c < used_colors_size && used[c])
            c++;
        if (c >= used_colors_size)
        {
            used_colors_size *= 2;
            char *new_used = (char *)realloc(used, used_colors_size * sizeof(char));
            if (!new_used)
            {
                fprintf(stderr, "Memory reallocation failed!\n");
                free(color);
                free(used);
                exit(1);
            }
            used = new_used;
            memset(used + c, 0, (used_colors_size - c) * sizeof(char));
        }

        color[i] = c;
        if (c > max_color)
            max_color = c;

        // 清除标记
        for (JX_Int jj = U_i[i]; jj < U_i[i + 1]; jj++)
        {
            JX_Int col = U_j[jj];
            if (col < i && color[col] >= 0)
            {
                used[color[col]] = 0;
            }
        }
    }

    free(used);

    *num_colors_out = max_color + 1;

    // 统计每个颜色的数量
    JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
    for (JX_Int i = 0; i < nLU; i++)
        color_count[color[i]]++;

    // 构造 color_starts 数组
    JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
    color_starts[0] = 0;
    for (JX_Int c = 1; c <= *num_colors_out; c++)
        color_starts[c] = color_starts[c - 1] + color_count[c - 1];

    // 构造 row_by_color 数组，并保证每个颜色的行是按从大到小顺序排列（倒着写入）
    JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
    memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

    for (JX_Int i = nLU - 1; i >= 0; i--)
    {
        JX_Int c = color[i];
        row_by_color[temp_index[c]++] = i;
    }

    // === 构造 perm / inv_perm ===
    JX_Int *perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *inv_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));

    for (JX_Int new_i = 0; new_i < nLU; new_i++)
    {
        JX_Int old_i = row_by_color[new_i];
        perm[old_i] = new_i;
        inv_perm[new_i] = old_i;
    }

    // === 重排 U_diag 的行指针与数据 ===
    // 根据新的行顺序，重新排列 U 的行，但列索引保持不变。
    JX_Int *new_i = (JX_Int *)malloc((nLU + 1) * sizeof(JX_Int));
    JX_Int *row_nnz = (JX_Int *)calloc(nLU, sizeof(JX_Int));

    // 计算每一行的非零元数量（按旧顺序）
    for (JX_Int i = 0; i < nLU; i++)
    {
        JX_Int old_i = inv_perm[i];
        row_nnz[i] = U_i[old_i + 1] - U_i[old_i];
    }

    // 构造新的 row pointer 数组 new_i
    new_i[0] = 0;
    for (JX_Int i = 1; i <= nLU; i++)
    {
        new_i[i] = new_i[i - 1] + row_nnz[i - 1];
    }

    // 分配新存储空间
    JX_Int nnz = new_i[nLU];
    JX_Int *new_j = (JX_Int *)malloc(nnz * sizeof(JX_Int));
    JX_Real *new_data = (JX_Real *)malloc(nnz * sizeof(JX_Real));
    JX_Int *pos = (JX_Int *)calloc(nLU, sizeof(JX_Int));

    // 按新行顺序搬运旧数据
    for (JX_Int i = 0; i < nLU; i++)
    {
        JX_Int old_i = inv_perm[i];
        for (JX_Int jj = U_i[old_i]; jj < U_i[old_i + 1]; jj++)
        {
            JX_Int insert_pos = new_i[i] + pos[i];
            new_j[insert_pos] = U_j[jj];       // 列索引保持不变
            new_data[insert_pos] = U_data[jj]; // 数值保持不变
            pos[i]++;
        }
    }

    // 释放旧存储
    free(U_i);
    free(U_j);
    free(U_data);

    // 更新 U_diag 到新存储
    jx_CSRMatrixI(U_diag) = new_i;
    jx_CSRMatrixJ(U_diag) = new_j;
    jx_CSRMatrixData(U_diag) = new_data;

    // 输出结果
    *row_by_color_out = row_by_color;
    *color_starts_out = color_starts;
    *perm_out = perm;
    *inv_perm_out = inv_perm;

    // for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*perm_out)[i]);
    // printf("\n");
    // printf("inv_perm_out: ");
    // for (JX_Int i = 0; i <= nLU; i++) printf("%d ", (*inv_perm_out)[i]);
    // printf("\n");

    // // 打印调试信息
    // printf("Number of levels : %d\n", *num_colors_out);
    // printf("jlevU (row indices per level): ");
    // for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*row_by_color_out)[i]);
    // printf("\n");
    // printf("ilevU (level offsets): ");
    // for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", (*color_starts_out)[i]);
    // printf("\n");

    // 清理
    free(color_count);
    free(temp_index);
    free(color);
    free(row_nnz);
    free(pos);

    return 0;
}

// JX_Int
// jx_GreedyColoring_L1(jx_ParCSRMatrix *L,
//                   JX_Int           nLU,
//                   JX_Int         **row_by_color_out,
//                   JX_Int         **color_starts_out,
//                   JX_Int          *num_colors_out,
//                   JX_Int         **perm_out,
//                   JX_Int         **inv_perm_out)
// {
//     jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
//     JX_Int *L_i = jx_CSRMatrixI(L_diag);
//     JX_Int *L_j = jx_CSRMatrixJ(L_diag);
//     JX_Real *L_data = jx_CSRMatrixData(L_diag);

//     JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int used_colors_size = 16;
//     char *used = (char *)calloc(used_colors_size, sizeof(char));

//     for (JX_Int i = 0; i < nLU; i++) color[i] = -1;

//     JX_Int max_color = -1;

//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         // 标记当前行依赖的颜色
//         if (max_color >= 0) memset(used, 0, (max_color + 1) * sizeof(char));

//         for (JX_Int jj = L_i[i]; jj < L_i[i+1]; jj++)
//         {
//             JX_Int col = L_j[jj];
//             if (col < i && color[col] >= 0)
//             {
//                 used[color[col]] = 1;
//             }
//         }

//         // 选一个未使用的最小颜色
//         JX_Int c = 0;
//         while (c < used_colors_size && used[c]) c++;
//         if (c >= used_colors_size) {
//             used_colors_size *= 2;
//             char *new_used = (char *)realloc(used, used_colors_size * sizeof(char));
//             if (!new_used) {
//                 fprintf(stderr, "Memory reallocation failed!\n");
//                 free(color);
//                 free(used);
//                 exit(1);
//             }
//             used = new_used;
//             memset(used + c, 0, (used_colors_size - c) * sizeof(char));
//         }
//         color[i] = c;
//         if (c > max_color) max_color = c;

//         // 清除标记
//         for (JX_Int jj = L_i[i]; jj < L_i[i+1]; jj++)
//         {
//             JX_Int col = L_j[jj];
//             if (col < i && color[col] >= 0)
//             {
//                 used[color[col]] = 0;
//             }
//         }
//     }

//     free(used);
//     *num_colors_out = max_color + 1;

//     // 统计每个颜色的数量
//     JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++)
//         color_count[color[i]]++;

//     // 构造 color_starts 数组
//     JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
//     color_starts[0] = 0;
//     for (JX_Int c = 1; c <= *num_colors_out; c++)
//         color_starts[c] = color_starts[c - 1] + color_count[c - 1];

//     // 构造 row_by_color 数组
//     JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
//     memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         JX_Int c = color[i];
//         row_by_color[temp_index[c]++] = i;
//     }

//     // === 构造 perm / inv_perm ===
//     JX_Int *perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *inv_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     for (JX_Int new_i = 0; new_i < nLU; new_i++) {
//         JX_Int old_i = row_by_color[new_i];
//         perm[old_i] = new_i;
//         inv_perm[new_i] = old_i;
//     }

//     // === 重排 L_diag 到新顺序 ===
//     JX_Int *new_i = (JX_Int *)malloc((nLU + 1) * sizeof(JX_Int));
//     JX_Int *row_nnz = (JX_Int *)calloc(nLU, sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int old_i = inv_perm[i];
//         row_nnz[i] = L_i[old_i + 1] - L_i[old_i];
//     }

//     new_i[0] = 0;
//     for (JX_Int i = 1; i <= nLU; i++)
//         new_i[i] = new_i[i - 1] + row_nnz[i - 1];

//     JX_Int nnz = new_i[nLU];
//     JX_Int *new_j = (JX_Int *)malloc(nnz * sizeof(JX_Int));
//     JX_Real *new_data = (JX_Real *)malloc(nnz * sizeof(JX_Real));
//     JX_Int *pos = (JX_Int *)calloc(nLU, sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int old_i = inv_perm[i];
//         JX_Int row_start = L_i[old_i];
//         for (JX_Int jj = L_i[old_i]; jj < L_i[old_i + 1]; jj++) {
//             JX_Int old_j = L_j[jj];
//             JX_Int new_j_idx = perm[old_j];

//             JX_Int insert_pos = new_i[i] + pos[i];
//             new_j[insert_pos] = new_j_idx;
//             new_data[insert_pos] = L_data[jj];
//             pos[i]++;
//         }
//     }

//     // 替换原有 L_diag 内容
//     free(L_i);
//     free(L_j);
//     free(L_data);

//    jx_CSRMatrixData(L_diag ) = new_data;
//    jx_CSRMatrixI(L_diag ) = new_i;
//    jx_CSRMatrixJ(L_diag ) = new_j;

//    // === 生成 jlevL_perm（即 perm[row_by_color]） ===
//     JX_Int *row_by_color_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         row_by_color_perm[i] = perm[row_by_color[i]];
//     }

//     // 输出结果
//     *row_by_color_out = row_by_color_perm;
//     *color_starts_out = color_starts;
//     *perm_out = perm;
//     *inv_perm_out = inv_perm;

//     //  for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*perm_out)[i]);
//     // printf("\n");
//     // printf("inv_perm_out: ");
//     // for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*inv_perm_out)[i]);
//     // printf("\n");

//     // printf("Number of levels : %d\n", *num_colors_out);
//     // printf("jlevU (row indices per level): ");
//     // for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*row_by_color_out)[i]);
//     // printf("\n");
//     // printf("ilevU (level offsets): ");
//     // for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", (*color_starts_out)[i]);
//     // printf("\n");

//     // 清理
//     free(color_count);
//     free(temp_index);
//     free(color);
//    free(row_nnz);
//     free(pos);

//     return 0;
// }

// JX_Int jx_GreedyColoring_U1(jx_ParCSRMatrix *U,
//                                  JX_Int           nLU,
//                                  JX_Int         **row_by_color_out,
//                                  JX_Int         **color_starts_out,
//                                  JX_Int          *num_colors_out,
//                                  JX_Int         **perm_out,
//                                  JX_Int         **inv_perm_out)
// {
//     jx_CSRMatrix *U_diag = jx_ParCSRMatrixDiag(U);
//     JX_Int *U_i = jx_CSRMatrixI(U_diag);
//     JX_Int *U_j = jx_CSRMatrixJ(U_diag);
//     JX_Real *U_data = jx_CSRMatrixData(U_diag);

//     JX_Int *color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int used_colors_size = 16;
//     char *used = (char *)calloc(used_colors_size, sizeof(char));

//     for (JX_Int i = 0; i < nLU; i++) color[i] = -1;

//     JX_Int max_color = -1;

//     // 从最后一行开始染色，让最后一行最先染、染成颜色0
//     for (JX_Int i = nLU - 1; i >= 0; i--)
//     {
//         if (max_color >= 0)
//             memset(used, 0, (max_color + 1) * sizeof(char));

//         // 当前行依赖于行号更小的行（下三角）
//         for (JX_Int jj = U_i[i]; jj < U_i[i+1]; jj++)
//         {
//             JX_Int col = U_j[jj];
//             if (col > i && color[col] >= 0)
//             {
//                 used[color[col]] = 1;
//             }
//         }

//         // 选择未用的最小颜色
//         JX_Int c = 0;
//         while (c < used_colors_size && used[c]) c++;
//         if (c >= used_colors_size)
//         {
//             used_colors_size *= 2;
//             char *new_used = (char *)realloc(used, used_colors_size * sizeof(char));
//             if (!new_used)
//             {
//                 fprintf(stderr, "Memory reallocation failed!\n");
//                 free(color);
//                 free(used);
//                 exit(1);
//             }
//             used = new_used;
//             memset(used + c, 0, (used_colors_size - c) * sizeof(char));
//         }

//         color[i] = c;
//         if (c > max_color) max_color = c;

//         // 清除标记
//         for (JX_Int jj = U_i[i]; jj < U_i[i+1]; jj++)
//         {
//             JX_Int col = U_j[jj];
//             if (col < i && color[col] >= 0)
//             {
//                 used[color[col]] = 0;
//             }
//         }
//     }

//     free(used);

//     *num_colors_out = max_color + 1;

//     // 统计每个颜色的数量
//     JX_Int *color_count = (JX_Int *)calloc(*num_colors_out, sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++)
//         color_count[color[i]]++;

//     // 构造 color_starts 数组
//     JX_Int *color_starts = (JX_Int *)malloc((*num_colors_out + 1) * sizeof(JX_Int));
//     color_starts[0] = 0;
//     for (JX_Int c = 1; c <= *num_colors_out; c++)
//         color_starts[c] = color_starts[c - 1] + color_count[c - 1];

//     // 构造 row_by_color 数组，并保证每个颜色的行是按从大到小顺序排列（倒着写入）
//     JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *temp_index = (JX_Int *)malloc(*num_colors_out * sizeof(JX_Int));
//     memcpy(temp_index, color_starts, *num_colors_out * sizeof(JX_Int));

//     for (JX_Int i = nLU - 1; i >= 0; i--)
//     {
//         JX_Int c = color[i];
//         row_by_color[temp_index[c]++] = i;
//     }
//     //     // === 构造 perm / inv_perm ===
//     // JX_Int *perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     // JX_Int *inv_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     // for (JX_Int new_i = 0; new_i < nLU; new_i++) {
//     //     perm[new_i] = new_i;
//     //     inv_perm[new_i] = new_i;
//     // }

//     // === 构造 perm / inv_perm ===
//     JX_Int *perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *inv_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     for (JX_Int new_i = 0; new_i < nLU; new_i++) {
//         JX_Int old_i = row_by_color[nLU - 1 - new_i];
//         perm[old_i] = new_i;
//         inv_perm[new_i] = old_i;
//     }

//     // === 重排 U_diag 到新顺序 ===
//     JX_Int *new_i = (JX_Int *)malloc((nLU + 1) * sizeof(JX_Int));
//     JX_Int *row_nnz = (JX_Int *)calloc(nLU, sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int old_i = inv_perm[i];
//         row_nnz[i] = U_i[old_i + 1] - U_i[old_i];
//     }

//     new_i[0] = 0;
//     for (JX_Int i = 1; i <= nLU; i++)
//         new_i[i] = new_i[i - 1] + row_nnz[i - 1];

//     JX_Int nnz = new_i[nLU];
//     JX_Int *new_j = (JX_Int *)malloc(nnz * sizeof(JX_Int));
//     JX_Real *new_data = (JX_Real *)malloc(nnz * sizeof(JX_Real));
//     JX_Int *pos = (JX_Int *)calloc(nLU, sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int old_i = inv_perm[i];
//         for (JX_Int jj = U_i[old_i]; jj < U_i[old_i + 1]; jj++) {
//             JX_Int old_j = U_j[jj];
//             JX_Int new_j_idx = perm[old_j];

//             JX_Int insert_pos = new_i[i] + pos[i];
//             new_j[insert_pos] = new_j_idx;
//             new_data[insert_pos] = U_data[jj];
//             pos[i]++;
//         }
//     }

//     // 释放旧指针（确保无共享）
//     free(U_i);
//     free(U_j);
//     free(U_data);

//     // 更新 U_diag 指针
//     jx_CSRMatrixI(U_diag) = new_i;
//     jx_CSRMatrixJ(U_diag) = new_j;
//     jx_CSRMatrixData(U_diag) = new_data;

//     // === 生成 jlevU_perm（即 perm[row_by_color]） ===
//     JX_Int *row_by_color_perm = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++)
//     {
//         row_by_color_perm[i] = perm[row_by_color[i]];
//     }

//     // 输出结果
//     *row_by_color_out = row_by_color_perm;
//     *color_starts_out = color_starts;
//     *perm_out = perm;
//     *inv_perm_out = inv_perm;

//     // for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*perm_out)[i]);
//     // printf("\n");
//     // printf("inv_perm_out: ");
//     // for (JX_Int i = 0; i <= nLU; i++) printf("%d ", (*inv_perm_out)[i]);
//     // printf("\n");

//     //打印调试信息
//     // printf("Number of levels : %d\n", *num_colors_out);
//     // printf("jlevU (row indices per level): ");
//     // for (JX_Int i = 0; i < nLU; i++) printf("%d ", (*row_by_color_out)[i]);
//     // printf("\n");
//     // printf("ilevU (level offsets): ");
//     // for (JX_Int i = 0; i <= *num_colors_out; i++) printf("%d ", (*color_starts_out)[i]);
//     // printf("\n");

//     // 清理
//     free(color_count);
//     free(temp_index);
//     free(color);
//    free(row_nnz);
//     free(pos);

//     return 0;
// }

// 对称矩阵A染色
// JX_Int jx_GreedyColoring(jx_ParCSRMatrix *A,
//                                JX_Int          nLU,
//                                JX_Int         **row_by_color_out,
//                                JX_Int         **color_starts_out,
//                                JX_Int          *num_colors_out)
//  {
//      jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//      JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//      JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);

//     // 分配并初始化颜色数组为-1（未着色）
//     JX_Int *color = (JX_Int *)calloc(nLU, sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++) color[i] = -1;

//     // 用于标记节点是否已着色
//     char *colored = (char *)calloc(nLU, sizeof(char));
//     JX_Int *level = (JX_Int *)calloc(nLU, sizeof(JX_Int)); // 节点着色等级

//     // 初始化所有节点为0级
//     for (JX_Int i = 0; i < nLU; i++) level[i] = 0;

//     // 多级着色
//     JX_Int current_color = 0;
//     JX_Int remaining = nLU;

//     while (remaining > 0) {
//         JX_Int colored_this_round = 0;

//         // 遍历所有未着色节点
//         for (JX_Int i = 0; i < nLU; i++) {
//             if (colored[i]) continue; // 已着色节点跳过

//             // 检查是否所有依赖节点都已完成（颜色值小于当前颜色）
//             JX_Int can_color = 1;

//             // 检查所有邻居（包括前向和后向依赖）
//             for (JX_Int jj = A_diag_i[i]; jj < A_diag_i[i+1]; jj++) {
//                 JX_Int neighbor = A_diag_j[jj];

//                 // 如果邻居已着色且颜色相同，则冲突
//                 if (colored[neighbor] && color[neighbor] == current_color) {
//                     can_color = 0;
//                     break;
//                 }

//                 // 如果邻居未着色但依赖关系更强，则等待
//                 if (!colored[neighbor] && level[neighbor] < level[i]) {
//                     can_color = 0;
//                     break;
//                 }
//             }

//             if (can_color) {
//                 color[i] = current_color;
//                 colored[i] = 1;
//                 colored_this_round++;
//             } else {
//                 // 无法着色，提升等级以便下轮考虑
//                 level[i]++;
//             }
//         }

//         if (colored_this_round == 0) {
//             // 处理可能出现的死锁：找出最小等级节点强制着色
//             JX_Int min_level = nLU + 1;
//             JX_Int min_index = -1;

//             for (JX_Int i = 0; i < nLU; i++) {
//                 if (!colored[i] && level[i] < min_level) {
//                     min_level = level[i];
//                     min_index = i;
//                 }
//             }

//             if (min_index >= 0) {
//                 color[min_index] = current_color;
//                 colored[min_index] = 1;
//                 colored_this_round = 1;
//             }
//         }

//         remaining -= colored_this_round;
//         current_color++;
//     }

//     // 统计颜色分布
//     JX_Int *color_counts = (JX_Int *)calloc(current_color, sizeof(JX_Int));
//     for (JX_Int i = 0; i < nLU; i++) {
//         color_counts[color[i]]++;
//     }

//     // 创建颜色起始索引
//     JX_Int *color_starts = (JX_Int *)malloc((current_color + 1) * sizeof(JX_Int));
//     color_starts[0] = 0;
//     for (JX_Int c = 0; c < current_color; c++) {
//         color_starts[c + 1] = color_starts[c] + color_counts[c];
//     }

//     // 按颜色排序节点
//     JX_Int *row_by_color = (JX_Int *)malloc(nLU * sizeof(JX_Int));
//     JX_Int *temp_counts = (JX_Int *)malloc(current_color * sizeof(JX_Int));
//     memcpy(temp_counts, color_starts, current_color * sizeof(JX_Int));

//     for (JX_Int i = 0; i < nLU; i++) {
//         JX_Int c = color[i];
//         row_by_color[temp_counts[c]++] = i;
//     }

//     // 设置输出
//     *row_by_color_out = row_by_color;
//     *color_starts_out = color_starts;
//     *num_colors_out = current_color;

//     printf("GS iteration coloring completed: total colors = %d\n",  current_color);

//     // 清理
//     free(color);
//     free(colored);
//     free(level);
//     free(color_counts);
//     free(temp_counts);

//     return 0; // 成功
// }

JX_Int jx_GreedyColoring_8GS(jx_ParCSRMatrix *A,
                             JX_Int nLU,
                             JX_Int **row_by_color_out,
                             JX_Int **color_starts_out,
                             JX_Int *num_colors_out,
                             JX_Int **row_by_color_out1,
                             JX_Int **color_starts_out1,
                             JX_Int *num_colors_out1)
{
   JX_Int nx = 127; //(JX_Int)(round(pow((double)nLU, 1.0 / 3.0)));
   JX_Int ny = 127;
   JX_Int nz = 127;

    if (nx * ny * nz != nLU) {
        printf("Error: Grid size %d x %d x %d does not match global rows %d\n", nx, ny, nz, nLU);
        return -1;
    }

    /*======================= 正向着色 ========================*/
    JX_Int *color_count = (JX_Int *)calloc(8, sizeof(JX_Int));
    for (JX_Int local_row = 0; local_row < nLU; local_row++) {
        JX_Int i = local_row % nx;
        JX_Int j = (local_row / nx) % ny;
        JX_Int k = local_row / (nx * ny);
        JX_Int color = (i % 2) + (j % 2) * 2 + (k % 2) * 4;
        color_count[color]++;
    }

    *row_by_color_out = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    *color_starts_out = (JX_Int *)malloc(9 * sizeof(JX_Int));
    (*color_starts_out)[0] = 0;
    for (JX_Int c = 0; c < 8; c++) {
        (*color_starts_out)[c + 1] = (*color_starts_out)[c] + color_count[c];
    }
    *num_colors_out = 8;

    JX_Int *temp_count = (JX_Int *)calloc(8, sizeof(JX_Int));
    for (JX_Int c = 0; c < 8; c++) {
        temp_count[c] = (*color_starts_out)[c];
    }
    for (JX_Int local_row = 0; local_row < nLU; local_row++) {
        JX_Int i = local_row % nx;
        JX_Int j = (local_row / nx) % ny;
        JX_Int k = local_row / (nx * ny);
        JX_Int color = (i % 2) + (j % 2) * 2 + (k % 2) * 4;
        (*row_by_color_out)[temp_count[color]++] = local_row;
    }

    /*======================= 反向着色 ========================*/
    // 计算最后一个点的原始颜色
    JX_Int last_r = nLU - 1;
    JX_Int i_last = last_r % nx;
    JX_Int j_last = (last_r / nx) % ny;
    JX_Int k_last = last_r / (nx * ny);
    JX_Int base_color = (i_last % 2) + (j_last % 2) * 2 + (k_last % 2) * 4;

    JX_Int *colors = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    JX_Int *color_count1 = (JX_Int *)calloc(8, sizeof(JX_Int));
    for (JX_Int r = 0; r < nLU; r++) {
        JX_Int i = r % nx;
        JX_Int j = (r / nx) % ny;
        JX_Int k = r / (nx * ny);
        JX_Int orig_color = (i % 2) + (j % 2) * 2 + (k % 2) * 4;
        colors[r] = (orig_color - base_color + 8) % 8;
        color_count1[colors[r]]++;
    }

    *row_by_color_out1 = (JX_Int *)malloc(nLU * sizeof(JX_Int));
    *color_starts_out1 = (JX_Int *)malloc(9 * sizeof(JX_Int));
    (*color_starts_out1)[0] = 0;
    for (JX_Int c = 0; c < 8; c++) {
        (*color_starts_out1)[c + 1] = (*color_starts_out1)[c] + color_count1[c];
    }
    *num_colors_out1 = 8;

    JX_Int *color_pos = (JX_Int *)calloc(8, sizeof(JX_Int));
    for (JX_Int c = 0; c < 8; c++) {
        color_pos[c] = (*color_starts_out1)[c];
    }

    for (JX_Int r = nLU - 1; r >= 0; r--) {
        JX_Int c = colors[r];
        (*row_by_color_out1)[color_pos[c]++] = r;
    }

    free(colors);
    free(color_count);
    free(color_count1);
    free(temp_count);
    free(color_pos);

    return 0;
}

// JX_Int jx_ILUSetupFGPILU_v3(jx_ParCSRMatrix *A,
//                             JX_Int sweep,
//                             jx_ParCSRMatrix **Lptr,
//                             jx_ParVector **D,
//                             jx_ParCSRMatrix **Uptr,
//                             jx_ParCSRMatrix **Sptr,
//                             JX_Int **u_end)
// {
//     MPI_Comm comm = jx_ParCSRMatrixComm(A);
//     JX_Int num_procs, my_id;
//     jx_ParCSRCommPkg *comm_pkg = NULL;

//     /* MPI initialization */
//     jx_MPI_Comm_size(comm, &num_procs);
//     jx_MPI_Comm_rank(comm, &my_id);

//     comm_pkg = jx_ParCSRMatrixCommPkg(A);
//     if (!comm_pkg)
//     {
//         jx_MatvecCommPkgCreate(A);
//         comm_pkg = jx_ParCSRMatrixCommPkg(A);
//     }

//     JX_Int i, j, k;
//     JX_Int ROW_OMP, temp_idx;
//     JX_Int nthreads = 1;
//     JX_Real local_nnz = 0.0, total_nnz = 0.0;

//     /* Data objects for A */
//     jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//     JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
//     JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//     JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
//     JX_Int n = jx_CSRMatrixNumRows(A_diag);
//     JX_Int nnz_A = A_diag_i[n];

//     JX_Int first_col_diag_A = jx_ParCSRMatrixFirstColDiag(A);
//     JX_Int num_cols_diag_A = jx_CSRMatrixNumCols(A_diag);
//     JX_Int last_col_diag_A = first_col_diag_A + num_cols_diag_A - 1;
//     JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

//     /* Data objects for L, D, U */
//     jx_ParCSRMatrix *matL = NULL, *matU = NULL;
//     jx_CSRMatrix *L_diag = NULL, *U_diag = NULL;
//     JX_Real *D_data = NULL;
//     JX_Real *d_data = NULL;
//     JX_Real *L_diag_data = NULL, *U_diag_data = NULL;
//     JX_Int *L_diag_i = NULL, *L_diag_j = NULL;
//     JX_Int *U_diag_i = NULL, *U_diag_j = NULL;
//     JX_Int *workL = NULL, *workU = NULL;
//     JX_Int *workLO = NULL, *workUO = NULL;
//     JX_Int LD_nnz = 0, UD_nnz = 0;

//     /* temporaries for C = A - L*U */
//     JX_Real *C_diag_data = NULL;

//     JX_Int nt = 1;
//     JX_Int global_row, global_col;

//     /* Data objects for A */
//     jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
//     JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);
//     JX_Int *A_offd_i = jx_CSRMatrixI(A_offd);
//     JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
//     JX_Int nnz_AO = A_offd_i[n];

//     JX_Int num_cols_offd_A =  jx_CSRMatrixNumCols(A_offd);
//     JX_Int L_offd_cols =  jx_CSRMatrixNumCols(A_offd);
//     JX_Int U_offd_cols =  jx_CSRMatrixNumCols(A_offd);

//     jx_CSRMatrix *L_offd = NULL, *U_offd = NULL;
//     JX_Real *L_offd_data = NULL, *U_offd_data = NULL;
//     JX_Int *L_offd_i = NULL, *L_offd_j = NULL;
//     JX_Int *U_offd_i = NULL, *U_offd_j = NULL;
//     JX_Int LO_nnz = 0, UO_nnz = 0;

//     JX_Real *C_offd_data = NULL;

//     C_diag_data = jx_TAlloc(JX_Real, nnz_A);
//     C_offd_data = jx_TAlloc(JX_Real, nnz_AO);

//     /* Thread info */
//     nt = jx_NumActiveThreads();
//     if (nt <= 0)
//         nt = 1;
//     nthreads = nt;

//     ROW_OMP = (n + nt - 1) / nt;

//     /* allocate prefix arrays (per-thread) */
//     workL = jx_TAlloc(JX_Int, nt + 1);
//     workU = jx_TAlloc(JX_Int, nt + 1);

//     workLO = jx_TAlloc(JX_Int, nt + 1);
//     workUO = jx_TAlloc(JX_Int, nt + 1);
//     if (!workL || !workU)
//     {
//         fprintf(stderr, "Memory alloc failure workL/workU\n");
//         jx_TFree(workL);
//         jx_TFree(workU);
//         return -1;
//     }
//     for (i = 0; i <= nt; i++)
//     {
//         workL[i] = 0;
//         workU[i] = 0;
//     }
     
// /* 1) Count diag (local) lower/upper nnz per-thread */
// #pragma omp parallel num_threads(nt)
//     {
//         JX_Int tid = jx_GetThreadNum();
//         JX_Int istart = tid * ROW_OMP;
//         JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//         JX_Int localL = 0, localU = 0;
//         for (JX_Int r = istart; r < iend && r < n; r++)
//         {
//             for (JX_Int jj = A_diag_i[r]; jj < A_diag_i[r + 1]; jj++)
//             {
//                 JX_Int col = A_diag_j[jj];
//                 if (col < r)
//                     localL++;
//                 else if (col > r)
//                     localU++;
//             }
//         }
//         workL[tid + 1] = localL;
//         workU[tid + 1] = localU;
// #pragma omp barrier
// #pragma omp single
//         {
//             for (JX_Int t = 1; t <= nt; t++)
//             {
//                 workL[t] += workL[t - 1];
//                 workU[t] += workU[t - 1];
//             }
//         }
//     }

//     LD_nnz = workL[nt];
//     UD_nnz = workU[nt];

//     /* allocate diag arrays */
//     D_data = jx_TAlloc(JX_Real, n);
//     d_data = jx_TAlloc(JX_Real, n);

//     L_diag_i = jx_TAlloc(JX_Int, n + 1);
//     U_diag_i = jx_TAlloc(JX_Int, n + 1);
//     L_diag_j = jx_TAlloc(JX_Int, LD_nnz);
//     U_diag_j = jx_TAlloc(JX_Int, UD_nnz);
//     L_diag_data = jx_TAlloc(JX_Real, LD_nnz);
//     U_diag_data = jx_TAlloc(JX_Real, UD_nnz);

// /* fill diag index/data from A (split into L/U and diagonal) */
// #pragma omp parallel num_threads(nt)
//     {
//         JX_Int tid = jx_GetThreadNum();
//         JX_Int istart = tid * ROW_OMP;
//         JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//         JX_Int cntL = 0, cntU = 0;
//         for (JX_Int r = istart; r < iend && r < n; r++)
//         {
//             L_diag_i[r] = workL[tid] + cntL;  //构建偏移指针
//             U_diag_i[r] = workU[tid] + cntU;
//             for (JX_Int jj = A_diag_i[r]; jj < A_diag_i[r + 1]; jj++)
//             {
//                 JX_Int col = A_diag_j[jj];
//                 JX_Real aval = A_diag_data[jj];
//                 if (col < r)
//                 {
//                     L_diag_j[workL[tid] + cntL] = col;
//                     L_diag_data[workL[tid] + cntL] = D_data[r] * aval;
//                     cntL++;
//                 }
//                 else if (col > r)
//                 {
//                     U_diag_j[workU[tid] + cntU] = col;
//                     U_diag_data[workU[tid] + cntU] = aval;
//                     cntU++;
//                 }
//                 else
//                 {
//                     d_data[r] = aval;
//                     /* guard diagonal */
//                     if (fabs(d_data[r]) < MAT_TOL)
//                     {
//                         d_data[r] = (JX_Real)1e-6;
//                     }
//                     D_data[r] = (JX_Real)1.0 / d_data[r];
//                 }
//             }
//         }
//     }
//     L_diag_i[n] = LD_nnz;
//     U_diag_i[n] = UD_nnz;

//     if (num_procs > 1)
//     {
//         /* reset work arrays for offd counting */
//         for (i = 0; i <= nt; i++)
//         {
//             workLO[i] = 0;
//             workUO[i] = 0;
//         }

// /* 2) Count offd lower/upper nnz per-thread (use global compare) */
// #pragma omp parallel num_threads(nt)
//         {
//             JX_Int tid = jx_GetThreadNum();
//             JX_Int istart = tid * ROW_OMP;
//             JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//             JX_Int localL = 0, localU = 0;
//             for (JX_Int r = istart; r < iend && r < n; r++)
//             {
//                 JX_Int global_row_idx = r + first_col_diag_A;
//                 for (JX_Int jj = A_offd_i[r]; jj < A_offd_i[r + 1]; jj++)
//                 {
//                     JX_Int offd_col_idx = A_offd_j[jj]; /* index into col_map_offd_A */
//                     JX_Int global_col_idx = col_map_offd_A[offd_col_idx];
//                     if (global_col_idx < global_row_idx)
//                         localL++;
//                     else if (global_col_idx > global_row_idx)
//                         localU++;
//                 }
//             }
//             workLO[tid + 1] = localL;
//             workUO[tid + 1] = localU;
// #pragma omp barrier
// #pragma omp single
//             {
//                 for (JX_Int t = 1; t <= nt; t++)
//                 {
//                     workLO[t] += workLO[t - 1];
//                     workUO[t] += workUO[t - 1];
//                 }
//             }
//         }

//         LO_nnz = workLO[nt];
//         UO_nnz = workUO[nt];

//         /* allocate offd arrays */
//         L_offd_i = jx_TAlloc(JX_Int, n + 1);
//         U_offd_i = jx_TAlloc(JX_Int, n + 1);
//         L_offd_j = jx_TAlloc(JX_Int, LO_nnz);
//         U_offd_j = jx_TAlloc(JX_Int, UO_nnz);
//         L_offd_data = jx_TAlloc(JX_Real, LO_nnz);
//         U_offd_data = jx_TAlloc(JX_Real, UO_nnz);

// /* fill offd structures from A */
// #pragma omp parallel num_threads(nt)
//         {
//             JX_Int tid = jx_GetThreadNum();
//             JX_Int istart = tid * ROW_OMP;
//             JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//             JX_Int cntL = 0, cntU = 0;
//             for (JX_Int r = istart; r < iend && r < n; r++)
//             {
//                 L_offd_i[r] = workLO[tid] + cntL;
//                 U_offd_i[r] = workUO[tid] + cntU;
//                 JX_Int global_row_idx = r + first_col_diag_A;
//                 for (JX_Int jj = A_offd_i[r]; jj < A_offd_i[r + 1]; jj++)
//                 {
//                     JX_Int offd_idx = A_offd_j[jj];
//                     JX_Int global_col_idx = col_map_offd_A[offd_idx];
//                     JX_Real aval = A_offd_data[jj];
//                     if (global_col_idx < global_row_idx)
//                     {
//                         L_offd_j[workLO[tid] + cntL] = offd_idx;
//                         L_offd_data[workLO[tid] + cntL] = D_data[r] * aval;
//                         cntL++;
//                     }
//                     else   //(global_col_idx > global_row_idx)
//                     {
//                         U_offd_j[workUO[tid] + cntU] = offd_idx;
//                         U_offd_data[workUO[tid] + cntU] = aval;
//                         cntU++;
//                     }
//                 }
//             }
//         }
//         L_offd_i[n] = LO_nnz;
//         U_offd_i[n] = UO_nnz;
//     }

//     /* create ParCSR matrices matL and matU (structure only) */
//     matL = jx_ParCSRMatrixCreate(comm,
//                                  jx_ParCSRMatrixGlobalNumRows(A),
//                                  jx_ParCSRMatrixGlobalNumCols(A),
//                                  jx_ParCSRMatrixRowStarts(A),
//                                  jx_ParCSRMatrixColStarts(A),
//                                  L_offd_cols,
//                                  LD_nnz,
//                                  LO_nnz );
//     /* attach diag/offd pointers for L */
//     L_diag = jx_ParCSRMatrixDiag(matL);
//     jx_CSRMatrixI(L_diag) = L_diag_i;
//     jx_CSRMatrixJ(L_diag) = L_diag_j;
//     jx_CSRMatrixData(L_diag) = L_diag_data;
//     // jx_CSRMatrixNumRows(L_diag); /* just ensure object exists */
//     // /* offd */
//     // jx_ParCSRMatrixOffd(matL);       /* ensure offd exists if function provided */
//     // jx_ParCSRMatrixColMapOffd(matL); /* ensure colmap exists if needed */

//     /* For U */
//     matU = jx_ParCSRMatrixCreate(comm,
//                                  jx_ParCSRMatrixGlobalNumRows(A),
//                                  jx_ParCSRMatrixGlobalNumCols(A),
//                                  jx_ParCSRMatrixRowStarts(A),
//                                  jx_ParCSRMatrixColStarts(A),
//                                  U_offd_cols,
//                                  UD_nnz,
//                                  UO_nnz);
//     U_diag = jx_ParCSRMatrixDiag(matU);
//     jx_CSRMatrixI(U_diag) = U_diag_i;
//     jx_CSRMatrixJ(U_diag) = U_diag_j;
//     jx_CSRMatrixData(U_diag) = U_diag_data;

//     if (num_procs > 1)
//     {
//         // JX_Int num_cols_offd_A = jx_ParCSRMatrixNumColsOffd(A);
//         // JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

//         /* offd 部分指针绑定 */
//         jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(matL);
//         jx_CSRMatrix *U_offd = jx_ParCSRMatrixOffd(matU);

//         jx_CSRMatrixI(L_offd) = L_offd_i;
//         jx_CSRMatrixJ(L_offd) = L_offd_j;
//         jx_CSRMatrixData(L_offd) = L_offd_data;
//         jx_CSRMatrixNumCols(L_offd) = L_offd_cols;

//         jx_CSRMatrixI(U_offd) = U_offd_i;
//         jx_CSRMatrixJ(U_offd) = U_offd_j;
//         jx_CSRMatrixData(U_offd) = U_offd_data;
//         jx_CSRMatrixNumCols(U_offd) = U_offd_cols;

//         /* col_map_offd 复制 */
//         JX_Int *col_map_offd_L = jx_CTAlloc(JX_Int, L_offd_cols);
//         JX_Int *col_map_offd_U = jx_CTAlloc(JX_Int, U_offd_cols);

//         if (num_cols_offd_A > 0 && col_map_offd_A)
//         {
//             for (i = 0; i < num_cols_offd_A; i++)
//             {
//                 col_map_offd_L[i] = col_map_offd_A[i];
//                 col_map_offd_U[i] = col_map_offd_A[i];
//             }
//         }
//         jx_ParCSRMatrixColMapOffd(matL) = col_map_offd_L;
//         jx_ParCSRMatrixColMapOffd(matU) = col_map_offd_U;

//         /* 通信包创建 */
//         jx_MatvecCommPkgCreate(matL);
//         jx_MatvecCommPkgCreate(matU);
//     }

//     /* MAIN SWEEPS: ILU iterations */
//     for (JX_Int sweep_it = 1; sweep_it < sweep; sweep_it++)
//     {
//         /* compute C = A - L * U (uses provided function to write to C_diag_data/C_offd_data) */
//         jx_ParCSRMatrixMatmul_Apattern(A, matL, matU, C_diag_data, C_offd_data);

//         #pragma omp parallel num_threads(nt)
//         {
//             JX_Int tid = jx_GetThreadNum();
//             JX_Int istart = tid * ROW_OMP;
//             JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//             for (JX_Int r = istart; r < iend && r < n; r++)
//             {
//                 j = A_diag_i[r]; 
//                 JX_Int col = A_diag_j[j];
//                 JX_Real aval = C_diag_data[j];
                    
//                 d_data[r] = aval;
//                 /* guard diagonal */
//                 if (fabs(d_data[r]) < MAT_TOL)
//                 {
//                     d_data[r] = (JX_Real)1e-6;
//                 }
//                 D_data[r] = (JX_Real)1.0 / d_data[r];
//             }
//             for (JX_Int r = istart; r < iend && r < n; r++)
//             {
//                 JX_Int localLpos = L_diag_i[r];
//                 JX_Int localUpos = U_diag_i[r];
//                 for (JX_Int jj = A_diag_i[r]; jj < A_diag_i[r + 1]; jj++)
//                 {
//                     JX_Int col = A_diag_j[jj];
//                     JX_Real cval = C_diag_data[jj];
//                     if (col < r)
//                     {
//                         /* store in L_diag_data at next free position for r */
//                         L_diag_data[localLpos++] = D_data[r] * cval;
//                     }
//                     else if (col > r)
//                     {
//                         U_diag_data[localUpos++] = cval;
//                     }
//                     else
//                     {
//                         /* diagonal: update d_data and D_data */
//                         d_data[r] = cval;
//                         if (fabs(d_data[r]) < MAT_TOL)
//                         {
//                             d_data[r] = (JX_Real)1e-6;
//                         }
//                         D_data[r] = (JX_Real)1.0 / d_data[r];  //对角元提前放的原因
//                     }
//                 }
//             }
//         } /* end omp parallel */

//         if (num_procs > 1)
//         {
//         #pragma omp parallel num_threads(nt)
//             {
//                 JX_Int tid = jx_GetThreadNum();
//                 JX_Int istart = tid * ROW_OMP;
//                 JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
//                 // JX_Int countL = 0, countU = 0;
//                 for (JX_Int r = istart; r < iend && r < n; r++)
//                 {
//                     /* iterate A_offd positions; we must know mapping from A_offd positions to L_offd/U_offd positions:
//                     earlier when we built L_offd_j/U_offd_j we used workL/workU offsets; we can reuse the same scheme:
//                     */
//                     JX_Int countU = L_offd_i[tid];
//                     JX_Int countL = U_offd_i[tid];
//                     JX_Int global_row_idx = r + first_col_diag_A;
//                     for (JX_Int jj = A_offd_i[r]; jj < A_offd_i[r + 1]; jj++)
//                     {
//                         JX_Int offd_idx = A_offd_j[jj];
//                         JX_Int gcol = col_map_offd_A[offd_idx];
//                         JX_Real cval = C_offd_data[jj];
//                         if (gcol > global_row_idx)
//                         {
//                             U_offd_data[countU] = cval;
//                             countU++;
//                         }
//                         else  // (gcol < global_row_idx)
//                         {
//                             L_offd_data[countL] = D_data[r] * cval;
//                             countL++;
//                         }
//                     } /* end A_offd loop */
//                 } /* end for rows */
//             } /* end omp parallel */
//         }

//     } /* end sweeps */

//     /* compute and set global nnz counts for matU and matL (double stored) */
//     local_nnz = (JX_Real)(UD_nnz + UO_nnz);
//     jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
//     jx_ParCSRMatrixDNumNonzeros(matU) = total_nnz;

//     local_nnz = (JX_Real)(LD_nnz + LO_nnz);
//     jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
//     jx_ParCSRMatrixDNumNonzeros(matL) = total_nnz;

//     jx_ParVector *D_array = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
//                                                jx_ParCSRMatrixGlobalNumRows(A),
//                                                jx_ParCSRMatrixRowStarts(A));
//     jx_ParVectorInitialize(D_array);

//     jx_Vector *D_local = jx_ParVectorLocalVector(D_array);
//     jx_VectorData(D_local) = D_data;


//     /* outputs */
//     *Lptr = matL;
//     // *Dptr = D_data;
//     *Uptr = matU;
//     *Sptr = NULL;
//     *u_end = NULL;
//     *D = D_array;

//     /* free temporaries */
//     jx_TFree(workL);
//     workL = NULL;
//     jx_TFree(workU);
//     workU = NULL;

//     jx_TFree(workLO);
//     workLO = NULL;
//     jx_TFree(workUO);
//     workUO = NULL;

//     jx_TFree(C_diag_data);
//     C_diag_data = NULL;
//     jx_TFree(C_offd_data);
//     C_offd_data = NULL;
//     jx_TFree(d_data);

//     /* don't free L/U arrays: returned via matL/matU ownership */

//     return 0;
// }

// void jx_ParCSRMatrixMatmul_Apattern(jx_ParCSRMatrix *A, jx_ParCSRMatrix *L, jx_ParCSRMatrix *B,
//                                     JX_Real *C_diag_data, JX_Real *C_offd_data)
// {

//     MPI_Comm comm = jx_ParCSRMatrixComm(A);
//     JX_Int num_procs;
//     jx_MPI_Comm_size(comm, &num_procs);

//     /* Basic pointers to A and B blocks */
//     jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//     jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
//     JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//     JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
//     JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
//     JX_Int *A_offd_i = jx_CSRMatrixI(A_offd);
//     JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
//     JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);

//     JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

//     JX_Int *my_diag_array;
//     JX_Int *my_offd_array;
//     JX_Int max_num_threads = jx_NumThreads();
//     my_diag_array = jx_CTAlloc(JX_Int, max_num_threads);
//     my_offd_array = jx_CTAlloc(JX_Int, max_num_threads);

//     jx_CSRMatrix *B_diag = jx_ParCSRMatrixDiag(B);
//     jx_CSRMatrix *B_offd = jx_ParCSRMatrixOffd(B);
//     JX_Int *B_diag_i = jx_CSRMatrixI(B_diag);
//     JX_Int *B_diag_j = jx_CSRMatrixJ(B_diag);
//     JX_Real *B_diag_data = jx_CSRMatrixData(B_diag);
//     JX_Int *B_offd_i = jx_CSRMatrixI(B_offd);
//     JX_Int *B_offd_j = jx_CSRMatrixJ(B_offd);
//     JX_Real *B_offd_data = jx_CSRMatrixData(B_offd);

//     jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
//     jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(L);
//     JX_Int *L_diag_i = jx_CSRMatrixI(L_diag);
//     JX_Int *L_diag_j = jx_CSRMatrixJ(L_diag);
//     JX_Real *L_diag_data = jx_CSRMatrixData(L_diag);
//     JX_Int *L_offd_i = jx_CSRMatrixI(L_offd);
//     JX_Int *L_offd_j = jx_CSRMatrixJ(L_offd);
//     JX_Real *L_offd_data = jx_CSRMatrixData(L_offd);

//     /* local sizes / meta */
//     JX_Int num_rows_diag_A = jx_CSRMatrixNumRows(A_diag);
//     JX_Int num_cols_diag_A = jx_CSRMatrixNumCols(A_diag);
//     JX_Int num_cols_offd_A = jx_CSRMatrixNumCols(A_offd);
//     JX_Int first_col_diag_A = jx_ParCSRMatrixFirstColDiag(A);
//     JX_Int last_col_diag_A = first_col_diag_A + num_cols_diag_A - 1;

//     JX_Int first_col_diag_B = jx_ParCSRMatrixFirstColDiag(B);
//     JX_Int num_cols_diag_B = jx_CSRMatrixNumCols(B_diag);
//     JX_Int last_col_diag_B = first_col_diag_B + num_cols_diag_B - 1;

//     jx_CSRMatrix *Bs_ext = NULL;
//     JX_Real *Bs_ext_data = NULL;
//     JX_Int *Bs_ext_i = NULL;
//     JX_Int *Bs_ext_j = NULL;
//     JX_Int *B_ext_diag_i = NULL, *B_ext_offd_i = NULL;
//     JX_Int *B_ext_diag_j = NULL, *B_ext_offd_j = NULL;
//     JX_Real *B_ext_diag_data = NULL, *B_ext_offd_data = NULL;
//     JX_Int B_ext_diag_size = 0, B_ext_offd_size = 0;

//     // /* For create C later (not used here, since C arrays provided) */
//     // JX_Int *row_starts_A = jx_ParCSRMatrixRowStarts(A);

//     if (num_procs > 1)
//     {
//         /*---------------------------------------------------------------------
//          * If there exists no CommPkg for A, a CommPkg is generated using
//          * equally load balanced partitionings within
//          * jx_ParCSRMatrixExtractBExt
//          *--------------------------------------------------------------------*/
//         Bs_ext = jx_ParCSRMatrixExtractBExt(B, A, 1);
//         Bs_ext_data = jx_CSRMatrixData(Bs_ext);
//         Bs_ext_i = jx_CSRMatrixI(Bs_ext);
//         Bs_ext_j = jx_CSRMatrixJ(Bs_ext);
//     }
//     B_ext_diag_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
//     B_ext_offd_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
//     B_ext_diag_size = 0;
//     B_ext_offd_size = 0;

//     // printf("1\n");

//     #if JX_USING_OPENMP
//     #pragma omp parallel
//     #endif
//     {
//         JX_Int size, rest, ii;
//         JX_Int ns, ne;
//         JX_Int i1, i, j;
//         JX_Int my_offd_size, my_diag_size;
//         JX_Int cnt_offd, cnt_diag;

//         JX_Int num_threads = jx_NumActiveThreads();

//         size = num_cols_offd_A / num_threads;
//         rest = num_cols_offd_A - size * num_threads;
//         ii = jx_GetThreadNum();
//         if (ii < rest)
//         {
//             ns = ii * size + ii;
//             ne = (ii + 1) * size + ii + 1;
//         }
//         else
//         {
//             ns = ii * size + rest;
//             ne = (ii + 1) * size + rest;
//         }

//         my_diag_size = 0;
//         my_offd_size = 0;
//         for (i = ns; i < ne; i++)
//         {
//             B_ext_diag_i[i] = my_diag_size;
//             B_ext_offd_i[i] = my_offd_size;
//             for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
//             {
//                 if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
//                 {
//                     my_offd_size++;
//                 }
//                 else
//                 {
//                     my_diag_size++;
//                 }
//             }
//         }
//         my_diag_array[ii] = my_diag_size;
//         my_offd_array[ii] = my_offd_size;

//         #if JX_USING_OPENMP
//         #pragma omp barrier
//         #endif

//         if (ii)
//         {
//             my_diag_size = my_diag_array[0];
//             my_offd_size = my_offd_array[0];
//             for (i1 = 1; i1 < ii; i1++)
//             {
//                 my_diag_size += my_diag_array[i1];
//                 my_offd_size += my_offd_array[i1];
//             }

//             for (i1 = ns; i1 < ne; i1++)
//             {
//                 B_ext_diag_i[i1] += my_diag_size;
//                 B_ext_offd_i[i1] += my_offd_size;
//             }
//         }
//         else
//         {
//             B_ext_diag_size = 0;
//             B_ext_offd_size = 0;
//             for (i1 = 0; i1 < num_threads; i1++)
//             {
//                 B_ext_diag_size += my_diag_array[i1];
//                 B_ext_offd_size += my_offd_array[i1];
//             }
//             B_ext_diag_i[num_cols_offd_A] = B_ext_diag_size;
//             B_ext_offd_i[num_cols_offd_A] = B_ext_offd_size;

//             if (B_ext_diag_size)
//             {
//                 B_ext_diag_j = jx_CTAlloc(JX_Int, B_ext_diag_size);
//                 B_ext_diag_data = jx_CTAlloc(JX_Real, B_ext_diag_size);
//             }
//             if (B_ext_offd_size)
//             {
//                 B_ext_offd_j = jx_CTAlloc(JX_Int, B_ext_offd_size);
//                 B_ext_offd_data = jx_CTAlloc(JX_Real, B_ext_offd_size);
//             }
//         }
        
//         #if JX_USING_OPENMP
//         #pragma omp barrier
//         #endif

//         cnt_offd = B_ext_offd_i[ns];
//         cnt_diag = B_ext_diag_i[ns];
//         for (i = ns; i < ne; i++)
//         {
//             for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
//                 if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
//                 {
//                     B_ext_offd_j[cnt_offd] = Bs_ext_j[j];
//                     B_ext_offd_data[cnt_offd++] = Bs_ext_data[j];
//                 }
//                 else
//                 {
//                     B_ext_diag_j[cnt_diag] = Bs_ext_j[j] - first_col_diag_B;
//                     B_ext_diag_data[cnt_diag++] = Bs_ext_data[j];
//                 }
//         }

//     #if JX_USING_OPENMP
//     #pragma omp barrier
//     #endif
//     }

//     JX_Int ii1, jj1, jj2, jj3, jj4;
//     JX_Int i2;
//     JX_Real a_entry;
//     JX_Int target_col;
//     JX_Int global_col;

//     /* offd part */
//     if (num_cols_offd_A)
//     {
//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             for (jj1 = A_offd_i[ii1]; jj1 < A_offd_i[ii1 + 1]; jj1++)
//             {
//                 C_offd_data[jj1] = A_offd_data[jj1];
//                 target_col = A_offd_j[jj1];
//                 global_col = col_map_offd_A[target_col];

//                 // L_offd * B_ext_offd
//                 if(num_procs > 1)
//                 {
//                     for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
//                     {
//                         i2 = L_offd_j[jj2];
//                         for (jj3 = B_ext_offd_i[i2]; jj3 < B_ext_offd_i[i2 + 1]; jj3++)
//                         {
//                             if (B_ext_offd_j[jj3] == global_col)
//                             {
//                                 C_offd_data[jj1] -= L_offd_data[jj2] * B_ext_offd_data[jj3];
//                             }
//                         }
//                     }
//                 }

//                 // L_diag * B_offd
//                 for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
//                 {
//                     i2 = L_diag_j[jj2];
//                     for (jj3 = B_offd_i[i2]; jj3 < B_offd_i[i2 + 1]; jj3++)
//                     {
//                         if (B_offd_j[jj3] == target_col)
//                         {
//                             C_offd_data[jj1] -= L_diag_data[jj2] * B_offd_data[jj3];
//                         }
//                     }
//                 }
//             }
//         }
//     }
//     // printf("4\n");


//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             for (jj1 = A_diag_i[ii1]; jj1 < A_diag_i[ii1 + 1]; jj1++)
//             {
//                 C_diag_data[jj1] = A_diag_data[jj1];
//                 target_col = A_diag_j[jj1];

//                 if(num_procs > 1)
//                 {
//                     // L_offd * B_ext_diag
//                     for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
//                     {
//                         i2 = L_offd_j[jj2];
//                         for (jj3 = B_ext_diag_i[i2]; jj3 < B_ext_diag_i[i2 + 1]; jj3++)
//                         {
//                             if (B_ext_diag_j[jj3] == target_col)
//                             {
//                                 C_diag_data[jj1] -= L_offd_data[jj2] * B_ext_diag_data[jj3];
//                             }
//                         }
//                     }
//                 }

//                 // L_diag * B_diag
//                 for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
//                 {
//                     i2 = L_diag_j[jj2];
//                     for (jj3 = B_diag_i[i2]; jj3 < B_diag_i[i2 + 1]; jj3++)
//                     {
//                         if (B_diag_j[jj3] == target_col)
//                         {
//                             C_diag_data[jj1] -= L_diag_data[jj2] * B_diag_data[jj3];
//                         }
//                     }
//                 }
//             }
//         }


//     if (num_procs > 1)
//     {
//     jx_CSRMatrixDestroy(Bs_ext);
//     Bs_ext = NULL;
//     }
    
//     jx_TFree(B_ext_diag_i);
//     if (B_ext_diag_size)
//     {
//     jx_TFree(B_ext_diag_j);
//     jx_TFree(B_ext_diag_data);
//     }
//     jx_TFree(B_ext_offd_i);
//     if (B_ext_offd_size)
//     {
//     jx_TFree(B_ext_offd_j);
//     jx_TFree(B_ext_offd_data);
//     }

//     jx_TFree(my_diag_array);
//     jx_TFree(my_offd_array);
//     return;
// }


// void jx_ParCSRMatrixMatmul_Apattern(jx_ParCSRMatrix *A, jx_ParCSRMatrix *L, jx_ParCSRMatrix *B,
//                                     JX_Real *C_diag_data, JX_Real *C_offd_data)
// {

//     MPI_Comm comm = jx_ParCSRMatrixComm(A);
//     JX_Int num_procs;
//     jx_MPI_Comm_size(comm, &num_procs);

//     /* Basic pointers to A and B blocks */
//     jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//     jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
//     JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//     JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
//     JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
//     JX_Int A_diag_nnz = jx_CSRMatrixNumNonzeros(A_diag);
//     JX_Int *A_offd_i = jx_CSRMatrixI(A_offd);
//     JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
//     JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);
//     JX_Int A_offd_nnz = jx_CSRMatrixNumNonzeros(A_offd);


//     JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

//     JX_Int *my_diag_array;
//     JX_Int *my_offd_array;
//     JX_Int max_num_threads = jx_NumThreads();
//     my_diag_array = jx_CTAlloc(JX_Int, max_num_threads);
//     my_offd_array = jx_CTAlloc(JX_Int, max_num_threads);

//     jx_CSRMatrix *B_diag = jx_ParCSRMatrixDiag(B);
//     jx_CSRMatrix *B_offd = jx_ParCSRMatrixOffd(B);
//     JX_Int *B_diag_i = jx_CSRMatrixI(B_diag);
//     JX_Int *B_diag_j = jx_CSRMatrixJ(B_diag);
//     JX_Real *B_diag_data = jx_CSRMatrixData(B_diag);
//     JX_Int *B_offd_i = jx_CSRMatrixI(B_offd);
//     JX_Int *B_offd_j = jx_CSRMatrixJ(B_offd);
//     JX_Real *B_offd_data = jx_CSRMatrixData(B_offd);

//     jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
//     jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(L);
//     JX_Int *L_diag_i = jx_CSRMatrixI(L_diag);
//     JX_Int *L_diag_j = jx_CSRMatrixJ(L_diag);
//     JX_Real *L_diag_data = jx_CSRMatrixData(L_diag);
//     JX_Int *L_offd_i = jx_CSRMatrixI(L_offd);
//     JX_Int *L_offd_j = jx_CSRMatrixJ(L_offd);
//     JX_Real *L_offd_data = jx_CSRMatrixData(L_offd);

//     /* local sizes / meta */
//     JX_Int num_rows_diag_A = jx_CSRMatrixNumRows(A_diag);
//     JX_Int num_cols_diag_A = jx_CSRMatrixNumCols(A_diag);
//     JX_Int num_cols_offd_A = jx_CSRMatrixNumCols(A_offd);
//     JX_Int first_col_diag_A = jx_ParCSRMatrixFirstColDiag(A);
//     JX_Int last_col_diag_A = first_col_diag_A + num_cols_diag_A - 1;

//     JX_Int first_col_diag_B = jx_ParCSRMatrixFirstColDiag(B);
//     JX_Int num_cols_diag_B = jx_CSRMatrixNumCols(B_diag);
//     JX_Int last_col_diag_B = first_col_diag_B + num_cols_diag_B - 1;

//     jx_CSRMatrix *Bs_ext = NULL;
//     JX_Real *Bs_ext_data = NULL;
//     JX_Int *Bs_ext_i = NULL;
//     JX_Int *Bs_ext_j = NULL;
//     JX_Int *B_ext_diag_i = NULL, *B_ext_offd_i = NULL;
//     JX_Int *B_ext_diag_j = NULL, *B_ext_offd_j = NULL;
//     JX_Real *B_ext_diag_data = NULL, *B_ext_offd_data = NULL;
//     JX_Int B_ext_diag_size = 0, B_ext_offd_size = 0;

//     // /* For create C later (not used here, since C arrays provided) */
//     // JX_Int *row_starts_A = jx_ParCSRMatrixRowStarts(A);

//     if (num_procs > 1)
//     {
//         /*---------------------------------------------------------------------
//          * If there exists no CommPkg for A, a CommPkg is generated using
//          * equally load balanced partitionings within
//          * jx_ParCSRMatrixExtractBExt
//          *--------------------------------------------------------------------*/
//         Bs_ext = jx_ParCSRMatrixExtractBExt(B, A, 1);
//         Bs_ext_data = jx_CSRMatrixData(Bs_ext);
//         Bs_ext_i = jx_CSRMatrixI(Bs_ext);
//         Bs_ext_j = jx_CSRMatrixJ(Bs_ext);
//     }
//     B_ext_diag_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
//     B_ext_offd_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
//     B_ext_diag_size = 0;
//     B_ext_offd_size = 0;

//     // printf("1\n");

//     #if JX_USING_OPENMP
//     #pragma omp parallel
//     #endif
//     {
//         JX_Int size, rest, ii;
//         JX_Int ns, ne;
//         JX_Int i1, i, j;
//         JX_Int my_offd_size, my_diag_size;
//         JX_Int cnt_offd, cnt_diag;

//         JX_Int num_threads = jx_NumActiveThreads();

//         size = num_cols_offd_A / num_threads;
//         rest = num_cols_offd_A - size * num_threads;
//         ii = jx_GetThreadNum();
//         if (ii < rest)
//         {
//             ns = ii * size + ii;
//             ne = (ii + 1) * size + ii + 1;
//         }
//         else
//         {
//             ns = ii * size + rest;
//             ne = (ii + 1) * size + rest;
//         }

//         my_diag_size = 0;
//         my_offd_size = 0;
//         for (i = ns; i < ne; i++)
//         {
//             B_ext_diag_i[i] = my_diag_size;
//             B_ext_offd_i[i] = my_offd_size;
//             for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
//             {
//                 if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
//                 {
//                     my_offd_size++;
//                 }
//                 else
//                 {
//                     my_diag_size++;
//                 }
//             }
//         }
//         my_diag_array[ii] = my_diag_size;
//         my_offd_array[ii] = my_offd_size;

//         #if JX_USING_OPENMP
//         #pragma omp barrier
//         #endif

//         if (ii)
//         {
//             my_diag_size = my_diag_array[0];
//             my_offd_size = my_offd_array[0];
//             for (i1 = 1; i1 < ii; i1++)
//             {
//                 my_diag_size += my_diag_array[i1];
//                 my_offd_size += my_offd_array[i1];
//             }

//             for (i1 = ns; i1 < ne; i1++)
//             {
//                 B_ext_diag_i[i1] += my_diag_size;
//                 B_ext_offd_i[i1] += my_offd_size;
//             }
//         }
//         else
//         {
//             B_ext_diag_size = 0;
//             B_ext_offd_size = 0;
//             for (i1 = 0; i1 < num_threads; i1++)
//             {
//                 B_ext_diag_size += my_diag_array[i1];
//                 B_ext_offd_size += my_offd_array[i1];
//             }
//             B_ext_diag_i[num_cols_offd_A] = B_ext_diag_size;
//             B_ext_offd_i[num_cols_offd_A] = B_ext_offd_size;

//             if (B_ext_diag_size)
//             {
//                 B_ext_diag_j = jx_CTAlloc(JX_Int, B_ext_diag_size);
//                 B_ext_diag_data = jx_CTAlloc(JX_Real, B_ext_diag_size);
//             }
//             if (B_ext_offd_size)
//             {
//                 B_ext_offd_j = jx_CTAlloc(JX_Int, B_ext_offd_size);
//                 B_ext_offd_data = jx_CTAlloc(JX_Real, B_ext_offd_size);
//             }
//         }
        
//         #if JX_USING_OPENMP
//         #pragma omp barrier
//         #endif

//         cnt_offd = B_ext_offd_i[ns];
//         cnt_diag = B_ext_diag_i[ns];
//         for (i = ns; i < ne; i++)
//         {
//             for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
//                 if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
//                 {
//                     B_ext_offd_j[cnt_offd] = Bs_ext_j[j];
//                     B_ext_offd_data[cnt_offd++] = Bs_ext_data[j];
//                 }
//                 else
//                 {
//                     B_ext_diag_j[cnt_diag] = Bs_ext_j[j] - first_col_diag_B;
//                     B_ext_diag_data[cnt_diag++] = Bs_ext_data[j];
//                 }
//         }

//     #if JX_USING_OPENMP
//     #pragma omp barrier
//     #endif
//     }

//     JX_Int ii1, jj1, jj2, jj3, jj4;
//     JX_Int i2;
//     JX_Real a_entry;
//     JX_Int target_col;
//     JX_Int global_col;

//     memcpy(C_diag_data, A_diag_data, A_diag_nnz * sizeof(JX_Real));
//     memcpy(C_offd_data, A_offd_data, A_offd_nnz * sizeof(JX_Real));

//     /* offd part */
//     if (num_cols_offd_A)
//     {
//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_offd_j[jj2];
//                 for (jj3 = B_ext_offd_i[i2]; jj3 < B_ext_offd_i[i2 + 1]; jj3++)
//                 {
//                     for (jj1 = A_offd_i[ii1]; jj1 < A_offd_i[ii1 + 1]; jj1++)
//                     {
//                         target_col = A_offd_j[jj1];
//                         global_col = col_map_offd_A[target_col];
//                         if(B_ext_offd_j[jj3] == global_col)
//                         {
//                             C_offd_data[jj1] -= L_offd_data[jj2] * B_ext_offd_data[jj3];
//                         }
//                     }
//                 }
//             }

//         // L_diag * B_offd
//             for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_diag_j[jj2];
//                 for (jj3 = B_offd_i[i2]; jj3 < B_offd_i[i2 + 1]; jj3++)
//                 {
//                     for (jj1 = A_offd_i[ii1]; jj1 < A_offd_i[ii1 + 1]; jj1++)
//                     {
//                         if(B_offd_j[jj3] == A_offd_j[jj1])
//                         {
//                             C_offd_data[jj1] -= L_diag_data[jj2] * B_offd_data[jj3];
//                         }
//                     }
//                 }
//             }
//         }

//         for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_offd_j[jj2];
//                 for (jj3 = B_ext_diag_i[i2]; jj3 < B_ext_diag_i[i2 + 1]; jj3++)
//                 {
//                     target_col = B_ext_diag_j[jj3];
//                     for (jj1 = A_diag_i[ii1]; jj1 < A_diag_i[ii1 + 1]; jj1++)
//                     {
//                         if(A_diag_j[jj1] == target_col)
//                         {
//                             C_diag_data[jj1] -= L_offd_data[jj2] * B_ext_diag_data[jj3];
//                         }
//                     }
//                 }
//             }
//     }

//     // L_offd * B_ext_diag
//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             // L_diag * B_diag
//             for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_diag_j[jj2];
//                 for (jj3 = B_diag_i[i2]; jj3 < B_diag_i[i2 + 1]; jj3++)
//                 {
//                     target_col = B_diag_j[jj3];
//                     for (jj1 = A_diag_i[ii1]; jj1 < A_diag_i[ii1 + 1]; jj1++)
//                     {
//                         if(A_diag_j[jj1] == target_col)
//                         {
//                             C_diag_data[jj1] -= L_diag_data[jj2] * B_diag_data[jj3];
//                         }
//                     }
//                 }
//             }
//         }

//     if (num_procs > 1)
//     {
//     jx_CSRMatrixDestroy(Bs_ext);
//     Bs_ext = NULL;
//     }
    
//     jx_TFree(B_ext_diag_i);
//     if (B_ext_diag_size)
//     {
//     jx_TFree(B_ext_diag_j);
//     jx_TFree(B_ext_diag_data);
//     }
//     jx_TFree(B_ext_offd_i);
//     if (B_ext_offd_size)
//     {
//     jx_TFree(B_ext_offd_j);
//     jx_TFree(B_ext_offd_data);
//     }

//     jx_TFree(my_diag_array);
//     jx_TFree(my_offd_array);
//     return;
// }



JX_Int jx_ILUSetupFGPILU_v3(jx_ParCSRMatrix *A,
                            JX_Int sweep,
                            jx_ParCSRMatrix **Lptr,
                            jx_ParVector **D,
                            jx_ParCSRMatrix **Uptr,
                            jx_ParCSRMatrix **Sptr,
                            JX_Int **u_end)
{
    MPI_Comm comm = jx_ParCSRMatrixComm(A);
    JX_Int num_procs, my_id;
    jx_ParCSRCommPkg *comm_pkg = NULL;

    /* MPI initialization */
    jx_MPI_Comm_size(comm, &num_procs);
    jx_MPI_Comm_rank(comm, &my_id);

    comm_pkg = jx_ParCSRMatrixCommPkg(A);
    if (!comm_pkg)
    {
        jx_MatvecCommPkgCreate(A);
        comm_pkg = jx_ParCSRMatrixCommPkg(A);
    }

    JX_Int i, j, k;
    JX_Int ROW_OMP, temp_idx;
    JX_Int nthreads = 1;
    JX_Real local_nnz = 0.0, total_nnz = 0.0;

    /* Data objects for A */
    jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
    JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
    JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
    JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
    JX_Int n = jx_CSRMatrixNumRows(A_diag);
    JX_Int nnz_A = A_diag_i[n];

    JX_Int first_col_diag_A = jx_ParCSRMatrixFirstColDiag(A);
    JX_Int num_cols_diag_A = jx_CSRMatrixNumCols(A_diag);
    JX_Int last_col_diag_A = first_col_diag_A + num_cols_diag_A - 1;
    JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);
    // JX_Int L_offd_cols =  0;
    // JX_Int U_offd_cols =  0;

    /* Data objects for L, D, U */
    jx_ParCSRMatrix *matL = NULL, *matU = NULL;
    jx_CSRMatrix *L_diag = NULL, *U_diag = NULL;
    JX_Real *D_data = NULL;
    JX_Real *d_data = NULL;
    JX_Real *L_diag_data = NULL, *U_diag_data = NULL;
    JX_Int *L_diag_i = NULL, *L_diag_j = NULL;
    JX_Int *U_diag_i = NULL, *U_diag_j = NULL;
    JX_Int *workL = NULL, *workU = NULL;
    JX_Int *workLO = NULL, *workUO = NULL;  //add
    JX_Int LD_nnz = 0, UD_nnz = 0;

    /* temporaries for C = A - L*U */
    JX_Real *C_diag_data = NULL;

    JX_Int nt = 1;
    JX_Int global_row, global_col;

    /* Data objects for A */
    jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
    JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);
    JX_Int *A_offd_i = jx_CSRMatrixI(A_offd);
    JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
    JX_Int nnz_AO = A_offd_i[n];

    JX_Int num_cols_offd_A =  jx_CSRMatrixNumCols(A_offd);
    JX_Int L_offd_cols =  jx_CSRMatrixNumCols(A_offd);
    JX_Int U_offd_cols =  jx_CSRMatrixNumCols(A_offd);

    jx_CSRMatrix *L_offd = NULL, *U_offd = NULL;
    JX_Real *L_offd_data = NULL, *U_offd_data = NULL;
    JX_Int *L_offd_i = NULL, *L_offd_j = NULL;
    JX_Int *U_offd_i = NULL, *U_offd_j = NULL;
    JX_Int LO_nnz = 0, UO_nnz = 0;

    JX_Real *C_offd_data = NULL;

    C_diag_data = jx_TAlloc(JX_Real, nnz_A);
    C_offd_data = jx_TAlloc(JX_Real, nnz_AO);

    /* Thread info */
    nt = jx_NumActiveThreads();
    if (nt <= 0)
        nt = 1;
    nthreads = nt;

    ROW_OMP = (n + nt - 1) / nt;

    /* allocate prefix arrays (per-thread) */
    workL = jx_TAlloc(JX_Int, nt + 1);
    workU = jx_TAlloc(JX_Int, nt + 1);
    workLO = jx_TAlloc(JX_Int, nt + 1);
    workUO = jx_TAlloc(JX_Int, nt + 1);
    if (!workL || !workU)
    {
        fprintf(stderr, "Memory alloc failure workL/workU\n");
        jx_TFree(workL);
        jx_TFree(workU);
        return -1;
    }
    for (i = 0; i <= nt; i++)
    {
        workL[i] = 0;
        workU[i] = 0;
    }

/* 1) Count diag (local) lower/upper nnz per-thread */
#pragma omp parallel num_threads(nt)
    {
        JX_Int tid = jx_GetThreadNum();
        JX_Int istart = tid * ROW_OMP;
        JX_Int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
        JX_Int localL = 0, localU = 0;
        for (JX_Int r = istart; r < iend && r < n; r++)
        {
            for (JX_Int jj = A_diag_i[r]; jj < A_diag_i[r + 1]; jj++)
            {
                JX_Int col = A_diag_j[jj];
                if (col < r)
                    localL++;
                else if (col > r)
                    localU++;
            }
        }
        workL[tid + 1] = localL;
        workU[tid + 1] = localU;
#pragma omp barrier
#pragma omp single
        {
            for (JX_Int t = 1; t <= nt; t++)
            {
                workL[t] += workL[t - 1];
                workU[t] += workU[t - 1];
            }
        }
    }

    LD_nnz = workL[nt];
    UD_nnz = workU[nt];

    /* allocate diag arrays */
    D_data = jx_TAlloc(JX_Real, n);
    d_data = jx_TAlloc(JX_Real, n);

    L_diag_i = jx_TAlloc(JX_Int, n + 1);
    U_diag_i = jx_TAlloc(JX_Int, n + 1);
    L_diag_j = jx_TAlloc(JX_Int, LD_nnz);
    U_diag_j = jx_TAlloc(JX_Int, UD_nnz);
    L_diag_data = jx_TAlloc(JX_Real, LD_nnz);
    U_diag_data = jx_TAlloc(JX_Real, UD_nnz);

// C_diag_data = jx_TAlloc(JX_Real, nnz_A);

/* fill diag index/data from A (split into L/U and diagonal) */
#pragma omp parallel num_threads(nt)
    {
        int tid = jx_GetThreadNum();
        int istart = tid * ROW_OMP;
        int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
        int cntL = 0, cntU = 0;
        for (int r = istart; r < iend && r < n; r++)
        {
            L_diag_i[r] = workL[tid] + cntL;
            U_diag_i[r] = workU[tid] + cntU;
            for (int jj = A_diag_i[r]; jj < A_diag_i[r + 1]; jj++)
            {
                JX_Int col = A_diag_j[jj];
                JX_Real aval = A_diag_data[jj];
                if (col < r)
                {
                    L_diag_j[workL[tid] + cntL] = col;
                    L_diag_data[workL[tid] + cntL] = D_data[col] * aval;
                    cntL++;
                }
                else if (col > r)
                {
                    U_diag_j[workU[tid] + cntU] = col;
                    U_diag_data[workU[tid] + cntU] = aval;
                    cntU++;
                }
                else
                {
                    d_data[r] = aval;
                    /* guard diagonal */
                    if (fabs(d_data[r]) < MAT_TOL)
                        d_data[r] = (JX_Real)1e-6;
                    D_data[r] = (JX_Real)1.0 / d_data[r];
                }
            }
        }
    }
    L_diag_i[n] = LD_nnz;
    U_diag_i[n] = UD_nnz;

    if (num_procs > 1)
    {
        /* reset work arrays for offd counting */
        for (i = 0; i <= nt; i++)
        {
            workLO[i] = 0;
            workUO[i] = 0;
        }

/* 2) Count offd lower/upper nnz per-thread (use global compare) */
#pragma omp parallel num_threads(nt)
        {
            int tid = jx_GetThreadNum();
            int istart = tid * ROW_OMP;
            int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
            int localL = 0, localU = 0;
            for (int r = istart; r < iend && r < n; r++)
            {
                JX_Int global_row_idx = r + first_col_diag_A;
                for (int jj = A_offd_i[r]; jj < A_offd_i[r + 1]; jj++)
                {
                    JX_Int offd_col_idx = A_offd_j[jj]; /* index into col_map_offd_A */
                    JX_Int global_col_idx = col_map_offd_A[offd_col_idx];
                    if (global_col_idx < global_row_idx)
                        localL++;
                    else if (global_col_idx > global_row_idx)
                        localU++;
                }
            }
            workLO[tid + 1] = localL;
            workUO[tid + 1] = localU;
#pragma omp barrier
#pragma omp single
            {
                for (int t = 1; t <= nt; t++)
                {
                    workLO[t] += workLO[t - 1];
                    workUO[t] += workUO[t - 1];
                }
            }
        }

        LO_nnz = workLO[nt];
        UO_nnz = workUO[nt];

        /* allocate offd arrays */
        L_offd_i = jx_TAlloc(JX_Int, n + 1);
        U_offd_i = jx_TAlloc(JX_Int, n + 1);
        L_offd_j = jx_TAlloc(JX_Int, LO_nnz);
        U_offd_j = jx_TAlloc(JX_Int, UO_nnz);
        L_offd_data = jx_TAlloc(JX_Real, LO_nnz);
        U_offd_data = jx_TAlloc(JX_Real, UO_nnz);

// C_offd_data = jx_TAlloc(JX_Real, nnz_A);

/* fill offd structures from A */
#pragma omp parallel num_threads(nt)
        {
            int tid = jx_GetThreadNum();
            int istart = tid * ROW_OMP;
            int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
            int cntL = 0, cntU = 0;
            for (int r = istart; r < iend && r < n; r++)
            {
                L_offd_i[r] = workLO[tid] + cntL;
                U_offd_i[r] = workUO[tid] + cntU;
                JX_Int global_row_idx = r + first_col_diag_A;
                for (int jj = A_offd_i[r]; jj < A_offd_i[r + 1]; jj++)
                {
                    JX_Int offd_idx = A_offd_j[jj];
                    JX_Int global_col_idx = col_map_offd_A[offd_idx];
                    JX_Real aval = A_offd_data[jj];
                    if (global_col_idx < global_row_idx)
                    {
                        L_offd_j[workLO[tid] + cntL] = offd_idx;
                        L_offd_data[workLO[tid] + cntL] =aval;
                        cntL++;
                    }
                    else //if (global_col_idx > global_row_idx)
                    {
                        U_offd_j[workUO[tid] + cntU] = offd_idx;
                        U_offd_data[workUO[tid] + cntU] = aval;
                        cntU++;
                    }
                }
            }
        }
        L_offd_i[n] = LO_nnz;
        U_offd_i[n] = UO_nnz;
    }

    /* create ParCSR matrices matL and matU (structure only) */
    matL = jx_ParCSRMatrixCreate(comm,
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumCols(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A),
                                 L_offd_cols,
                                 LD_nnz,
                                 LO_nnz );
    /* attach diag/offd pointers for L */
    L_diag = jx_ParCSRMatrixDiag(matL);
    jx_CSRMatrixI(L_diag) = L_diag_i;
    jx_CSRMatrixJ(L_diag) = L_diag_j;
    jx_CSRMatrixData(L_diag) = L_diag_data;
    // jx_CSRMatrixNumRows(L_diag); /* just ensure object exists */
    // /* offd */
    // jx_ParCSRMatrixOffd(matL);       /* ensure offd exists if function provided */
    // jx_ParCSRMatrixColMapOffd(matL); /* ensure colmap exists if needed */

    /* For U */
    matU = jx_ParCSRMatrixCreate(comm,
                                 jx_ParCSRMatrixGlobalNumRows(A),
                                 jx_ParCSRMatrixGlobalNumCols(A),
                                 jx_ParCSRMatrixRowStarts(A),
                                 jx_ParCSRMatrixColStarts(A),
                                 U_offd_cols,
                                 UD_nnz,
                                 UO_nnz);
    U_diag = jx_ParCSRMatrixDiag(matU);
    jx_CSRMatrixI(U_diag) = U_diag_i;
    jx_CSRMatrixJ(U_diag) = U_diag_j;
    jx_CSRMatrixData(U_diag) = U_diag_data;

    jx_ParVector *D_array = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
                                               jx_ParCSRMatrixGlobalNumRows(A),
                                               jx_ParCSRMatrixRowStarts(A));
    jx_ParVectorInitialize(D_array);
    jx_Vector *D_local = jx_ParVectorLocalVector(D_array);
    jx_VectorData(D_local) = D_data;

    // if (num_procs > 1)
    // {
    //     jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(matL);
    //     jx_CSRMatrix *U_offd = jx_ParCSRMatrixOffd(matU);
    //     jx_CSRMatrixI(L_offd) = L_offd_i;
    //     jx_CSRMatrixJ(L_offd) = L_offd_j;
    //     jx_CSRMatrixData(L_offd) = L_offd_data;
    //     jx_CSRMatrixI(U_offd) = U_offd_i;
    //     jx_CSRMatrixJ(U_offd) = U_offd_j;
    //     jx_CSRMatrixData(U_offd) = U_offd_data;
    // }

    if (num_procs > 1)
    {
        // JX_Int num_cols_offd_A = jx_ParCSRMatrixNumColsOffd(A);
        // JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

        /* offd 部分指针绑定 */
        jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(matL);
        jx_CSRMatrix *U_offd = jx_ParCSRMatrixOffd(matU);

        jx_CSRMatrixI(L_offd) = L_offd_i;
        jx_CSRMatrixJ(L_offd) = L_offd_j;
        jx_CSRMatrixData(L_offd) = L_offd_data;
        jx_CSRMatrixNumCols(L_offd) = L_offd_cols;

        jx_CSRMatrixI(U_offd) = U_offd_i;
        jx_CSRMatrixJ(U_offd) = U_offd_j;
        jx_CSRMatrixData(U_offd) = U_offd_data;
        jx_CSRMatrixNumCols(U_offd) = U_offd_cols;

        /* col_map_offd 复制 */
        JX_Int *col_map_offd_L = jx_CTAlloc(JX_Int, L_offd_cols);
        JX_Int *col_map_offd_U = jx_CTAlloc(JX_Int, U_offd_cols);

        if (num_cols_offd_A > 0 && col_map_offd_A)
        {
            for (i = 0; i < num_cols_offd_A; i++)
            {
                col_map_offd_L[i] = col_map_offd_A[i];
                col_map_offd_U[i] = col_map_offd_A[i];
            }
        }
        jx_ParCSRMatrixColMapOffd(matL) = col_map_offd_L;
        jx_ParCSRMatrixColMapOffd(matU) = col_map_offd_U;

        /* 通信包创建 */
        jx_MatvecCommPkgCreate(matL);
        jx_MatvecCommPkgCreate(matU);

        jx_ParCSRMatrixM( matL,D_array );
    }

    /* MAIN SWEEPS: ILU iterations */
    for (int sweep_it = 0; sweep_it < sweep; sweep_it++)
    {
        // /* compute C = A - L * U (uses provided function to write to C_diag_data/C_offd_data) */
        jx_ParCSRMatrixMatmul_Apattern(A, matL, matU, C_diag_data, C_offd_data);

#pragma omp parallel num_threads(nt)
        {
            int tid = jx_GetThreadNum();
            int istart = tid * ROW_OMP;
            int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
            for (int r = istart; r < iend && r < n; r++)
            {
                int localLpos = L_diag_i[r];
                int localUpos = U_diag_i[r];
                for (int jj = A_diag_i[r]; jj < A_diag_i[r + 1]; jj++)
                {
                    JX_Int col = A_diag_j[jj];
                    JX_Real cval = C_diag_data[jj];
                    if (col < r)
                    {
                        /* store in L_diag_data at next free position for r */
                        L_diag_data[localLpos++] = D_data[col] * cval;
                    }
                    else if (col > r)
                    {
                        U_diag_data[localUpos++] = cval;
                    }
                    else
                    {
                        /* diagonal: update d_data and D_data */
                        d_data[r] = cval;
                        if (fabs(d_data[r]) < MAT_TOL)
                            d_data[r] = (JX_Real)1e-6;
                        D_data[r] = (JX_Real)1.0 / d_data[r];
                    }
                }
            }
        } /* end omp parallel */

        if (num_procs > 1)
        {
#pragma omp parallel num_threads(nt)
            {
                int tid = jx_GetThreadNum();
                int istart = tid * ROW_OMP;
                int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
                for (int r = istart; r < iend && r < n; r++)
                {
                    /* iterate A_offd positions; we must know mapping from A_offd positions to L_offd/U_offd positions:
                    earlier when we built L_offd_j/U_offd_j we used workL/workU offsets; we can reuse the same scheme:
                    */
                    // JX_Int baseL = workL[tid];
                    // JX_Int baseU = workU[tid];
                    int baseL = L_offd_i[r];
                    int baseU = U_offd_i[r];
                    JX_Int global_row_idx = r + first_col_diag_A;
                    for (int jj = A_offd_i[r]; jj < A_offd_i[r + 1]; jj++)
                    {
                        JX_Int col = A_offd_j[jj];
                        JX_Int gcol = col_map_offd_A[col];
                        JX_Real cval = C_offd_data[jj];
                        if (gcol > global_row_idx)
                        {
                            /* place into U_offd: find target index in U_offd_j array:
                            We rely on the fact that earlier construction used:
                            U_offd_j[ workU[tid] + local_countU ] = offd_idx
                            So we simply do U_offd_data[ workU[tid] + local_countU ] = cval;
                            */
                            U_offd_data[baseU++] = cval;
                        }
                        else if (gcol < global_row_idx)
                        {
                            L_offd_data[baseL++] = cval;
                        }
                    } /* end A_offd loop */
                } /* end for rows */
            } /* end omp parallel */
            jx_ParCSRMatrixM( matL,D_array );
        }

    } /* end sweeps */
        // char FileNameCoaMat[256];
        // // // jx_sprintf(FileNameCoaMat, "A_CSR_%d", num_procs);
        // // // jx_ParCSRMatrixPrint(A, FileNameCoaMat);
        // jx_sprintf(FileNameCoaMat, "L_CSR_%d", num_procs);
        // jx_ParCSRMatrixPrint(matL, FileNameCoaMat);
        // jx_sprintf(FileNameCoaMat, "U_CSR_%d", num_procs);
        // jx_ParCSRMatrixPrint(matU, FileNameCoaMat);

        // if(my_id == 0 )
        // {
        //     for (JX_Int i = 0; i < n ; i++) 
        //     {
        //     printf("%lf ", D_data[i]);
        //     printf("\n");
        //     }
        //     for (JX_Int i = 0; i < nnz_AO ; i++) 
        //     {
        //     printf("%lf ", C_offd_data[i]);
        //     printf("\n");
        //     }
        //}



    /* compute and set global nnz counts for matU and matL (double stored) */
    local_nnz = (JX_Real)(UD_nnz + UO_nnz);
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matU) = total_nnz;

    local_nnz = (JX_Real)(LD_nnz + LO_nnz);
    jx_MPI_Allreduce(&local_nnz, &total_nnz, 1, JX_MPI_REAL, MPI_SUM, comm);
    jx_ParCSRMatrixDNumNonzeros(matL) = total_nnz;

    // jx_ParVector *D_array = jx_ParVectorCreate(jx_ParCSRMatrixComm(A),
    //                                            jx_ParCSRMatrixGlobalNumRows(A),
    //                                            jx_ParCSRMatrixRowStarts(A));
    // jx_ParVectorInitialize(D_array);

    // jx_Vector *D_local = jx_ParVectorLocalVector(D_array);
    // jx_VectorData(D_local) = D_data;

    /* outputs */
    *Lptr = matL;
    // *Dptr = D_data;
    *Uptr = matU;
    *Sptr = NULL;
    *u_end = NULL;
    *D = D_array;

    /* free temporaries */
    jx_TFree(workL);
    workL = NULL;
    jx_TFree(workU);
    workU = NULL;
    jx_TFree(C_diag_data);
    C_diag_data = NULL;
    jx_TFree(C_offd_data);
    C_offd_data = NULL;
    jx_TFree(d_data);

    /* don't free L/U arrays: returned via matL/matU ownership */

    return 0;
}


void jx_ParCSRMatrixMatmul_Apattern(jx_ParCSRMatrix *A, jx_ParCSRMatrix *L, jx_ParCSRMatrix *B,
                                    JX_Real *C_diag_data, JX_Real *C_offd_data)
{

     MPI_Comm comm = jx_ParCSRMatrixComm(A);
    JX_Int num_procs;
    jx_MPI_Comm_size(comm, &num_procs);

    /* Basic pointers to A and B blocks */
    jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
    jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
    JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
    JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
    JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
    JX_Int *A_offd_i = jx_CSRMatrixI(A_offd);
    JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
    JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);

    JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

    JX_Int *my_diag_array;
    JX_Int *my_offd_array;
    JX_Int max_num_threads = jx_NumThreads();
    my_diag_array = jx_CTAlloc(JX_Int, max_num_threads);
    my_offd_array = jx_CTAlloc(JX_Int, max_num_threads);

    jx_CSRMatrix *B_diag = jx_ParCSRMatrixDiag(B);
    jx_CSRMatrix *B_offd = jx_ParCSRMatrixOffd(B);
    JX_Int *B_diag_i = jx_CSRMatrixI(B_diag);
    JX_Int *B_diag_j = jx_CSRMatrixJ(B_diag);
    JX_Real *B_diag_data = jx_CSRMatrixData(B_diag);
    JX_Int *B_offd_i = jx_CSRMatrixI(B_offd);
    JX_Int *B_offd_j = jx_CSRMatrixJ(B_offd);
    JX_Real *B_offd_data = jx_CSRMatrixData(B_offd);

    jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
    jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(L);
    JX_Int *L_diag_i = jx_CSRMatrixI(L_diag);
    JX_Int *L_diag_j = jx_CSRMatrixJ(L_diag);
    JX_Real *L_diag_data = jx_CSRMatrixData(L_diag);
    JX_Int *L_offd_i = jx_CSRMatrixI(L_offd);
    JX_Int *L_offd_j = jx_CSRMatrixJ(L_offd);
    JX_Real *L_offd_data = jx_CSRMatrixData(L_offd);

    /* local sizes / meta */
    JX_Int num_rows_diag_A = jx_CSRMatrixNumRows(A_diag);
    JX_Int num_cols_diag_A = jx_CSRMatrixNumCols(A_diag);
    JX_Int num_cols_offd_A = jx_CSRMatrixNumCols(A_offd);
    JX_Int first_col_diag_A = jx_ParCSRMatrixFirstColDiag(A);
    JX_Int last_col_diag_A = first_col_diag_A + num_cols_diag_A - 1;

    JX_Int first_col_diag_B = jx_ParCSRMatrixFirstColDiag(B);
    JX_Int num_cols_diag_B = jx_CSRMatrixNumCols(B_diag);
    JX_Int last_col_diag_B = first_col_diag_B + num_cols_diag_B - 1;

    jx_CSRMatrix *Bs_ext = NULL;
    JX_Real *Bs_ext_data = NULL;
    JX_Int *Bs_ext_i = NULL;
    JX_Int *Bs_ext_j = NULL;
    JX_Int *B_ext_diag_i = NULL, *B_ext_offd_i = NULL;
    JX_Int *B_ext_diag_j = NULL, *B_ext_offd_j = NULL;
    JX_Real *B_ext_diag_data = NULL, *B_ext_offd_data = NULL;
    JX_Int B_ext_diag_size = 0, B_ext_offd_size = 0;

    // /* For create C later (not used here, since C arrays provided) */
    // JX_Int *row_starts_A = jx_ParCSRMatrixRowStarts(A);
    if (num_procs > 1)
    {
        /*---------------------------------------------------------------------
         * If there exists no CommPkg for A, a CommPkg is generated using
         * equally load balanced partitionings within
         * jx_ParCSRMatrixExtractBExt
         *--------------------------------------------------------------------*/
        Bs_ext = jx_ParCSRMatrixExtractBExt(B, A, 1);
        Bs_ext_data = jx_CSRMatrixData(Bs_ext);
        Bs_ext_i = jx_CSRMatrixI(Bs_ext);
        Bs_ext_j = jx_CSRMatrixJ(Bs_ext);
    }
    B_ext_diag_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
    B_ext_offd_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
    B_ext_diag_size = 0;
    B_ext_offd_size = 0;

    #if JX_USING_OPENMP
    #pragma omp parallel
    #endif
    {
        JX_Int size, rest, ii;
        JX_Int ns, ne;
        JX_Int i1, i, j;
        JX_Int my_offd_size, my_diag_size;
        JX_Int cnt_offd, cnt_diag;

        JX_Int num_threads = jx_NumActiveThreads();

        size = num_cols_offd_A / num_threads;
        rest = num_cols_offd_A - size * num_threads;
        ii = jx_GetThreadNum();
        if (ii < rest)
        {
            ns = ii * size + ii;
            ne = (ii + 1) * size + ii + 1;
        }
        else
        {
            ns = ii * size + rest;
            ne = (ii + 1) * size + rest;
        }

        my_diag_size = 0;
        my_offd_size = 0;
        for (i = ns; i < ne; i++)
        {
            B_ext_diag_i[i] = my_diag_size;
            B_ext_offd_i[i] = my_offd_size;
            for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
            {
                if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
                {
                    my_offd_size++;
                }
                else
                {
                    my_diag_size++;
                }
            }
        }
        my_diag_array[ii] = my_diag_size;
        my_offd_array[ii] = my_offd_size;

        #if JX_USING_OPENMP
        #pragma omp barrier
        #endif
        if (ii)
        {
            my_diag_size = my_diag_array[0];
            my_offd_size = my_offd_array[0];
            for (i1 = 1; i1 < ii; i1++)
            {
                my_diag_size += my_diag_array[i1];
                my_offd_size += my_offd_array[i1];
            }

            for (i1 = ns; i1 < ne; i1++)
            {
                B_ext_diag_i[i1] += my_diag_size;
                B_ext_offd_i[i1] += my_offd_size;
            }
        }
        else
        {
            B_ext_diag_size = 0;
            B_ext_offd_size = 0;
            for (i1 = 0; i1 < num_threads; i1++)
            {
                B_ext_diag_size += my_diag_array[i1];
                B_ext_offd_size += my_offd_array[i1];
            }
            B_ext_diag_i[num_cols_offd_A] = B_ext_diag_size;
            B_ext_offd_i[num_cols_offd_A] = B_ext_offd_size;

            if (B_ext_diag_size)
            {
                B_ext_diag_j = jx_CTAlloc(JX_Int, B_ext_diag_size);
                B_ext_diag_data = jx_CTAlloc(JX_Real, B_ext_diag_size);
            }
            if (B_ext_offd_size)
            {
                B_ext_offd_j = jx_CTAlloc(JX_Int, B_ext_offd_size);
                B_ext_offd_data = jx_CTAlloc(JX_Real, B_ext_offd_size);
            }
        }
        
        #if JX_USING_OPENMP
        #pragma omp barrier
        #endif
        cnt_offd = B_ext_offd_i[ns];
        cnt_diag = B_ext_diag_i[ns];
        for (i = ns; i < ne; i++)
        {
            for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
                if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
                {
                    B_ext_offd_j[cnt_offd] = Bs_ext_j[j];
                    B_ext_offd_data[cnt_offd++] = Bs_ext_data[j];
                }
                else
                {
                    B_ext_diag_j[cnt_diag] = Bs_ext_j[j] - first_col_diag_B;
                    B_ext_diag_data[cnt_diag++] = Bs_ext_data[j];
                }
        }
    #if JX_USING_OPENMP
    #pragma omp barrier
    #endif
    }


    JX_Int ii1, jj1, jj2, jj3, jj4;
    JX_Int i2;
    JX_Real a_entry;
    JX_Int target_col;
    JX_Int global_col;
    /* offd part */
    if (num_cols_offd_A)
    {
        for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
        {
            for (jj1 = A_offd_i[ii1]; jj1 < A_offd_i[ii1 + 1]; jj1++)
            {
                C_offd_data[jj1] = A_offd_data[jj1];
                target_col = A_offd_j[jj1];
                global_col = col_map_offd_A[target_col];

                // L_offd * B_ext_offd
                for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
                {
                    i2 = L_offd_j[jj2];
                    for (jj3 = B_ext_offd_i[i2]; jj3 < B_ext_offd_i[i2 + 1]; jj3++)
                    {
                        if (B_ext_offd_j[jj3] == global_col)
                        {
                            C_offd_data[jj1] -= L_offd_data[jj2] * B_ext_offd_data[jj3];
                        }
                    }
                }

                // L_diag * B_offd
                for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
                {
                    i2 = L_diag_j[jj2];
                    for (jj3 = B_offd_i[i2]; jj3 < B_offd_i[i2 + 1]; jj3++)
                    {
                        if (B_offd_j[jj3] == target_col)
                        {
                            C_offd_data[jj1] -= L_diag_data[jj2] * B_offd_data[jj3];
                        }
                    }
                }
            }
        }
    }
    /* diag part */
    for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
    {
        for (jj1 = A_diag_i[ii1]; jj1 < A_diag_i[ii1 + 1]; jj1++)
        {
            C_diag_data[jj1] = A_diag_data[jj1];
            JX_Int target_col = A_diag_j[jj1];

            if (num_cols_offd_A)
            {
                // L_offd * B_ext_diag
                for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
                {
                    i2 = L_offd_j[jj2];
                    for (jj3 = B_ext_diag_i[i2]; jj3 < B_ext_diag_i[i2 + 1]; jj3++)
                    {
                        if (B_ext_diag_j[jj3] == target_col)
                        {
                            C_diag_data[jj1] -= L_offd_data[jj2] * B_ext_diag_data[jj3];
                        }
                    }
                }
            }
            // L_diag * B_diag
            for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
            {
                i2 = L_diag_j[jj2];
                for (jj3 = B_diag_i[i2]; jj3 < B_diag_i[i2 + 1]; jj3++)
                {
                    if (B_diag_j[jj3] == target_col)
                    {
                        C_diag_data[jj1] -= L_diag_data[jj2] * B_diag_data[jj3];
                    }
                }
            }
        }
    }

    jx_TFree(B_ext_diag_i);
        if (B_ext_diag_size)
        {
        jx_TFree(B_ext_diag_j);
        jx_TFree(B_ext_diag_data);
        }
    jx_TFree(B_ext_offd_i);
    if (B_ext_offd_size)
        {
        jx_TFree(B_ext_offd_j);
        jx_TFree(B_ext_offd_data);
        }

    jx_TFree(my_diag_array);
    jx_TFree(my_offd_array);
    return;
}


JX_Int
jx_ParCSRMatrixM(  jx_ParCSRMatrix *A,jx_ParVector    *x )
{
    jx_ParCSRCommHandle **comm_handle;
    jx_ParCSRCommPkg	*comm_pkg = jx_ParCSRMatrixCommPkg(A);
    jx_CSRMatrix         *diag     = jx_ParCSRMatrixDiag(A);
    JX_Int *diag_i = jx_CSRMatrixI(diag);
    JX_Int *diag_j = jx_CSRMatrixJ(diag);
    JX_Real *diag_data = jx_CSRMatrixData(diag);
    JX_Int n = jx_CSRMatrixNumRows(diag);
    JX_Int nt = jx_NumThreads();
    JX_Int ROW_OMP;
        
    jx_CSRMatrix         *offd     = jx_ParCSRMatrixOffd(A);
    JX_Int *offd_i = jx_CSRMatrixI(offd);
    JX_Int *offd_j = jx_CSRMatrixJ(offd);
    JX_Real *offd_data = jx_CSRMatrixData(offd);

    jx_Vector            *x_local  = jx_ParVectorLocalVector(x);   
    JX_Int         num_rows = jx_ParCSRMatrixGlobalNumRows(A);
    JX_Int         num_cols = jx_ParCSRMatrixGlobalNumCols(A);

    jx_Vector     *x_tmp;
    JX_Int        x_size = jx_ParVectorGlobalSize(x);
    JX_Int        num_vectors   = jx_VectorNumVectors(x_local);
    JX_Int	      num_cols_offd = jx_CSRMatrixNumCols(offd);
    JX_Int        ierr = 0;
    JX_Int	      num_sends, i, j, jv, index, start;

    JX_Int        vecstride = jx_VectorVectorStride( x_local );
    JX_Int        idxstride = jx_VectorIndexStride( x_local );

    JX_Real     *x_tmp_data, **x_buf_data;
    JX_Real     *x_local_data = jx_VectorData(x_local);

    JX_Real      wall_time = 0.0;  /* for debugging instrumentation  */

    if (jx__global_mvcpu_flag) wall_time = jx_time_getWallclockSeconds();
    
    /*---------------------------------------------------------------------
    *  Check for size compatibility.  ParMatvec returns ierr = 11 if
    *  length of X doesn't equal the number of columns of A,
    *  ierr = 12 if the length of Y doesn't equal the number of rows
    *  of A, and ierr = 13 if both are true.
    *
    *  Because temporary vectors are often used in ParMatvec, none of 
    *  these conditions terminates processing, and the ierr flag
    *  is informational only.
    *--------------------------------------------------------------------*/
 
    jx_assert( idxstride > 0 );

    // jx_assert( jx_VectorNumVectors(y_local)==num_vectors );

    if ( num_vectors == 1 )
    {
        x_tmp = jx_SeqVectorCreate( num_cols_offd );
    }
    else
    {
        jx_assert( num_vectors > 1 );
        x_tmp = jx_SeqMultiVectorCreate( num_cols_offd, num_vectors );
    }
    jx_SeqVectorInitialize(x_tmp);
    x_tmp_data = jx_VectorData(x_tmp);

    comm_handle = jx_CTAlloc(jx_ParCSRCommHandle*, num_vectors);

    /*---------------------------------------------------------------------
    * If there exists no CommPkg for A, a CommPkg is generated using
    * equally load balanced partitionings
    *--------------------------------------------------------------------*/
    
    if (!comm_pkg)
    {
        jx_MatvecCommPkgCreate(A);
        comm_pkg = jx_ParCSRMatrixCommPkg(A); 
    }

    num_sends = jx_ParCSRCommPkgNumSends(comm_pkg);
    x_buf_data = jx_CTAlloc(JX_Real *, num_vectors);
    for (jv = 0; jv < num_vectors; ++ jv)
    {
        x_buf_data[jv] = jx_CTAlloc( JX_Real, jx_ParCSRCommPkgSendMapStart(comm_pkg, num_sends) );
    }

    if ( num_vectors == 1 )
    {
        index = 0;
        for (i = 0; i < num_sends; i ++)
        {
            start = jx_ParCSRCommPkgSendMapStart(comm_pkg, i);
            for (j = start; j < jx_ParCSRCommPkgSendMapStart(comm_pkg, i+1); j ++)
            {
            x_buf_data[0][index++] = x_local_data[jx_ParCSRCommPkgSendMapElmt(comm_pkg,j)];
            }
        }
    }
    else
    {
        for (jv = 0; jv < num_vectors; ++ jv)
        {
            index = 0;
            for (i = 0; i < num_sends; i ++)
            {
                start = jx_ParCSRCommPkgSendMapStart(comm_pkg, i);
                for (j = start; j < jx_ParCSRCommPkgSendMapStart(comm_pkg, i+1); j ++)
                {
                        x_buf_data[jv][index++] 
                    = x_local_data[ jv*vecstride + idxstride*jx_ParCSRCommPkgSendMapElmt(comm_pkg,j) ];
                }
            }
        }
    }

    jx_assert( idxstride == 1 );
   
   /* >>> ... The assert is because the following loop only works for 'column' storage of a multivector <<<
      >>> This needs to be fixed to work more generally, at least for 'row' storage. <<<
      >>> This in turn, means either change CommPkg so num_sends is no.zones*no.vectors (not no.zones)
      >>> or, less dangerously, put a stride in the logic of CommHandleCreate (stride either from a
      >>> new arg or a new variable inside CommPkg).  Or put the num_vector iteration inside
      >>> CommHandleCreate (perhaps a new multivector variant of it). */
      
    for (jv = 0; jv < num_vectors; ++ jv)
    {
        comm_handle[jv] 
        = jx_ParCSRCommHandleCreate( 1, comm_pkg, x_buf_data[jv], &(x_tmp_data[jv*num_cols_offd]) );
    }

//    jx_CSRMatrixMatvec(alpha, diag, x_local, beta, y_local);

    
    for (jv = 0; jv < num_vectors; ++ jv)
    {
        jx_ParCSRCommHandleDestroy(comm_handle[jv]);
        comm_handle[jv] = NULL;
    }
    jx_TFree(comm_handle);

    ROW_OMP = (n + nt - 1) / nt;

    if (num_cols_offd) 
    {
    #pragma omp parallel num_threads(nt)
        {
            int tid = jx_GetThreadNum();
            int istart = tid * ROW_OMP;
            int iend = (tid + 1 == nt) ? n : (tid + 1) * ROW_OMP;
            for (int r = istart; r < iend && r < n; r++)
            {
                for (int jj = offd_i[r]; jj < offd_i[r+1]; jj++)
                {
                    JX_Int col = offd_j[jj];
                    offd_data[jj] = x_tmp_data[col] * offd_data[jj];
                } 
            }
        }
        // jx_CSRMatrixMatvec(alpha, offd, x_tmp, 1.0, y_local);

    }

   jx_SeqVectorDestroy(x_tmp);
   x_tmp = NULL;
   for (jv = 0; jv < num_vectors; ++ jv) 
   {
      jx_TFree(x_buf_data[jv]);
   }
   jx_TFree(x_buf_data);

   if (jx__global_mvcpu_flag) jx_total_elapsed_time_matvec += (jx_time_getWallclockSeconds() - wall_time);

   return ierr;
}



// void jx_ParCSRMatrixMatmul_Apattern(jx_ParCSRMatrix *A, jx_ParCSRMatrix *L, jx_ParCSRMatrix *B,
//                                     JX_Real *C_diag_data, JX_Real *C_offd_data)
// {

//     MPI_Comm comm = jx_ParCSRMatrixComm(A);
//     JX_Int num_procs;
//     jx_MPI_Comm_size(comm, &num_procs);

//     /* Basic pointers to A and B blocks */
//     jx_CSRMatrix *A_diag = jx_ParCSRMatrixDiag(A);
//     jx_CSRMatrix *A_offd = jx_ParCSRMatrixOffd(A);
//     JX_Int *A_diag_i = jx_CSRMatrixI(A_diag);
//     JX_Int *A_diag_j = jx_CSRMatrixJ(A_diag);
//     JX_Real *A_diag_data = jx_CSRMatrixData(A_diag);
//     JX_Int A_diag_nnz = jx_CSRMatrixNumNonzeros(A_diag);
//     JX_Int *A_offd_i = jx_CSRMatrixI(A_offd);
//     JX_Int *A_offd_j = jx_CSRMatrixJ(A_offd);
//     JX_Real *A_offd_data = jx_CSRMatrixData(A_offd);
//     JX_Int A_offd_nnz = jx_CSRMatrixNumNonzeros(A_offd);

//     JX_Int *col_map_offd_A = jx_ParCSRMatrixColMapOffd(A);

//     JX_Int *my_diag_array;
//     JX_Int *my_offd_array;
//     JX_Int max_num_threads = jx_NumThreads();
//     my_diag_array = jx_CTAlloc(JX_Int, max_num_threads);
//     my_offd_array = jx_CTAlloc(JX_Int, max_num_threads);

//     jx_CSRMatrix *B_diag = jx_ParCSRMatrixDiag(B);
//     jx_CSRMatrix *B_offd = jx_ParCSRMatrixOffd(B);
//     JX_Int *B_diag_i = jx_CSRMatrixI(B_diag);
//     JX_Int *B_diag_j = jx_CSRMatrixJ(B_diag);
//     JX_Real *B_diag_data = jx_CSRMatrixData(B_diag);
//     JX_Int *B_offd_i = jx_CSRMatrixI(B_offd);
//     JX_Int *B_offd_j = jx_CSRMatrixJ(B_offd);
//     JX_Real *B_offd_data = jx_CSRMatrixData(B_offd);

//     jx_CSRMatrix *L_diag = jx_ParCSRMatrixDiag(L);
//     jx_CSRMatrix *L_offd = jx_ParCSRMatrixOffd(L);
//     JX_Int *L_diag_i = jx_CSRMatrixI(L_diag);
//     JX_Int *L_diag_j = jx_CSRMatrixJ(L_diag);
//     JX_Real *L_diag_data = jx_CSRMatrixData(L_diag);
//     JX_Int *L_offd_i = jx_CSRMatrixI(L_offd);
//     JX_Int *L_offd_j = jx_CSRMatrixJ(L_offd);
//     JX_Real *L_offd_data = jx_CSRMatrixData(L_offd);

//     /* local sizes / meta */
//     JX_Int num_rows_diag_A = jx_CSRMatrixNumRows(A_diag);
//     JX_Int num_cols_diag_A = jx_CSRMatrixNumCols(A_diag);
//     JX_Int num_cols_offd_A = jx_CSRMatrixNumCols(A_offd);
//     JX_Int first_col_diag_A = jx_ParCSRMatrixFirstColDiag(A);
//     JX_Int last_col_diag_A = first_col_diag_A + num_cols_diag_A - 1;

//     JX_Int first_col_diag_B = jx_ParCSRMatrixFirstColDiag(B);
//     JX_Int num_cols_diag_B = jx_CSRMatrixNumCols(B_diag);
//     JX_Int last_col_diag_B = first_col_diag_B + num_cols_diag_B - 1;

//     jx_CSRMatrix *Bs_ext = NULL;
//     JX_Real *Bs_ext_data = NULL;
//     JX_Int *Bs_ext_i = NULL;
//     JX_Int *Bs_ext_j = NULL;
//     JX_Int *B_ext_diag_i = NULL, *B_ext_offd_i = NULL;
//     JX_Int *B_ext_diag_j = NULL, *B_ext_offd_j = NULL;
//     JX_Real *B_ext_diag_data = NULL, *B_ext_offd_data = NULL;
//     JX_Int B_ext_diag_size = 0, B_ext_offd_size = 0;

//     // /* For create C later (not used here, since C arrays provided) */
//     // JX_Int *row_starts_A = jx_ParCSRMatrixRowStarts(A);

//     if (num_procs > 1)
//     {
//         /*---------------------------------------------------------------------
//          * If there exists no CommPkg for A, a CommPkg is generated using
//          * equally load balanced partitionings within
//          * jx_ParCSRMatrixExtractBExt
//          *--------------------------------------------------------------------*/
//         Bs_ext = jx_ParCSRMatrixExtractBExt(B, A, 1);
//         Bs_ext_data = jx_CSRMatrixData(Bs_ext);
//         Bs_ext_i = jx_CSRMatrixI(Bs_ext);
//         Bs_ext_j = jx_CSRMatrixJ(Bs_ext);
//     }
//     B_ext_diag_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
//     B_ext_offd_i = jx_CTAlloc(JX_Int, num_cols_offd_A + 1);
//     B_ext_diag_size = 0;
//     B_ext_offd_size = 0;

//     #if JX_USING_OPENMP
//     #pragma omp parallel
//     #endif
//     {
//         JX_Int size, rest, ii;
//         JX_Int ns, ne;
//         JX_Int i1, i, j;
//         JX_Int my_offd_size, my_diag_size;
//         JX_Int cnt_offd, cnt_diag;

//         JX_Int num_threads = jx_NumActiveThreads();

//         size = num_cols_offd_A / num_threads;
//         rest = num_cols_offd_A - size * num_threads;
//         ii = jx_GetThreadNum();
//         if (ii < rest)
//         {
//             ns = ii * size + ii;
//             ne = (ii + 1) * size + ii + 1;
//         }
//         else
//         {
//             ns = ii * size + rest;
//             ne = (ii + 1) * size + rest;
//         }

//         my_diag_size = 0;
//         my_offd_size = 0;
//         for (i = ns; i < ne; i++)
//         {
//             B_ext_diag_i[i] = my_diag_size;
//             B_ext_offd_i[i] = my_offd_size;
//             for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
//             {
//                 if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
//                 {
//                     my_offd_size++;
//                 }
//                 else
//                 {
//                     my_diag_size++;
//                 }
//             }
//         }
//         my_diag_array[ii] = my_diag_size;
//         my_offd_array[ii] = my_offd_size;

//         #if JX_USING_OPENMP
//         #pragma omp barrier
//         #endif

//         if (ii)
//         {
//             my_diag_size = my_diag_array[0];
//             my_offd_size = my_offd_array[0];
//             for (i1 = 1; i1 < ii; i1++)
//             {
//                 my_diag_size += my_diag_array[i1];
//                 my_offd_size += my_offd_array[i1];
//             }

//             for (i1 = ns; i1 < ne; i1++)
//             {
//                 B_ext_diag_i[i1] += my_diag_size;
//                 B_ext_offd_i[i1] += my_offd_size;
//             }
//         }
//         else
//         {
//             B_ext_diag_size = 0;
//             B_ext_offd_size = 0;
//             for (i1 = 0; i1 < num_threads; i1++)
//             {
//                 B_ext_diag_size += my_diag_array[i1];
//                 B_ext_offd_size += my_offd_array[i1];
//             }
//             B_ext_diag_i[num_cols_offd_A] = B_ext_diag_size;
//             B_ext_offd_i[num_cols_offd_A] = B_ext_offd_size;

//             if (B_ext_diag_size)
//             {
//                 B_ext_diag_j = jx_CTAlloc(JX_Int, B_ext_diag_size);
//                 B_ext_diag_data = jx_CTAlloc(JX_Real, B_ext_diag_size);
//             }
//             if (B_ext_offd_size)
//             {
//                 B_ext_offd_j = jx_CTAlloc(JX_Int, B_ext_offd_size);
//                 B_ext_offd_data = jx_CTAlloc(JX_Real, B_ext_offd_size);
//             }
//         }
        
//         #if JX_USING_OPENMP
//         #pragma omp barrier
//         #endif

//         cnt_offd = B_ext_offd_i[ns];
//         cnt_diag = B_ext_diag_i[ns];
//         for (i = ns; i < ne; i++)
//         {
//             for (j = Bs_ext_i[i]; j < Bs_ext_i[i + 1]; j++)
//                 if (Bs_ext_j[j] < first_col_diag_B || Bs_ext_j[j] > last_col_diag_B)
//                 {
//                     B_ext_offd_j[cnt_offd] = Bs_ext_j[j];
//                     B_ext_offd_data[cnt_offd++] = Bs_ext_data[j];
//                 }
//                 else
//                 {
//                     B_ext_diag_j[cnt_diag] = Bs_ext_j[j] - first_col_diag_B;
//                     B_ext_diag_data[cnt_diag++] = Bs_ext_data[j];
//                 }
//         }

//     #if JX_USING_OPENMP
//     #pragma omp barrier
//     #endif
//     }

//     JX_Int ii1, jj1, jj2, jj3, jj4;
//     JX_Int i2;
//     JX_Real a_entry;
//     JX_Int target_col;
//     JX_Int global_col;

//     memcpy(C_diag_data, A_diag_data, A_diag_nnz * sizeof(JX_Real));
//     memcpy(C_offd_data, A_offd_data, A_offd_nnz * sizeof(JX_Real));

//     /* offd part */
//     if (num_cols_offd_A)
//     {
//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_offd_j[jj2];
//                 for (jj3 = B_ext_offd_i[i2]; jj3 < B_ext_offd_i[i2 + 1]; jj3++)
//                 {
//                     for (jj1 = A_offd_i[ii1]; jj1 < A_offd_i[ii1 + 1]; jj1++)
//                     {
//                         target_col = A_offd_j[jj1];
//                         global_col = col_map_offd_A[target_col];
//                         if(B_ext_offd_j[jj3] == global_col)
//                         {
//                             C_offd_data[jj1] -= L_offd_data[jj2] * B_ext_offd_data[jj3];
//                             break;
//                         }
//                     }
//                 }
//             }
//         }
        
//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             // L_diag * B_offd
//             for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_diag_j[jj2];
//                 for (jj3 = B_offd_i[i2]; jj3 < B_offd_i[i2 + 1]; jj3++)
//                 {
//                     for (jj1 = A_offd_i[ii1]; jj1 < A_offd_i[ii1 + 1]; jj1++)
//                     {
//                         if(B_offd_j[jj3] == A_offd_j[jj1])
//                         {
//                             C_offd_data[jj1] -= L_diag_data[jj2] * B_offd_data[jj3];
//                             break;
//                         }
//                     }
//                 }
//             }
//         }

//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             for (jj2 = L_offd_i[ii1]; jj2 < L_offd_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_offd_j[jj2];
//                 for (jj3 = B_ext_diag_i[i2]; jj3 < B_ext_diag_i[i2 + 1]; jj3++)
//                 {
//                     target_col = B_ext_diag_j[jj3];
//                     for (jj1 = A_diag_i[ii1]; jj1 < A_diag_i[ii1 + 1]; jj1++)
//                     {
//                         if(A_diag_j[jj1] == target_col)
//                         {
//                             C_diag_data[jj1] -= L_offd_data[jj2] * B_ext_diag_data[jj3];
//                             break;
//                         }
//                     }
//                 }
//             }
//         }
//     }

//     // L_offd * B_ext_diag
//         for (ii1 = 0; ii1 < num_rows_diag_A; ii1++)
//         {
//             // L_diag * B_diag
//             for (jj2 = L_diag_i[ii1]; jj2 < L_diag_i[ii1 + 1]; jj2++)
//             {
//                 i2 = L_diag_j[jj2];
//                 for (jj3 = B_diag_i[i2]; jj3 < B_diag_i[i2 + 1]; jj3++)
//                 {
//                     target_col = B_diag_j[jj3];
//                     for (jj1 = A_diag_i[ii1]; jj1 < A_diag_i[ii1 + 1]; jj1++)
//                     {
//                         if(A_diag_j[jj1] == target_col)
//                         {
//                             C_diag_data[jj1] -= L_diag_data[jj2] * B_diag_data[jj3];
//                             break;
//                         }
//                     }
//                 }
//             }
//         }

//     if (num_procs > 1)
//     {
//     jx_CSRMatrixDestroy(Bs_ext);
//     Bs_ext = NULL;
//     }
    
//     jx_TFree(B_ext_diag_i);
//     if (B_ext_diag_size)
//     {
//     jx_TFree(B_ext_diag_j);
//     jx_TFree(B_ext_diag_data);
//     }
//     jx_TFree(B_ext_offd_i);
//     if (B_ext_offd_size)
//     {
//     jx_TFree(B_ext_offd_j);
//     jx_TFree(B_ext_offd_data);
//     }

//     jx_TFree(my_diag_array);
//     jx_TFree(my_offd_array);
//     return;
// }
