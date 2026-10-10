/*----------------------------------------------------------------------------*/
/*  CP2K: A general program to perform molecular dynamics simulations         */
/*  Copyright 2000-2026 CP2K developers group <https://cp2k.org>              */
/*                                                                            */
/*  SPDX-License-Identifier: BSD-3-Clause                                     */
/*----------------------------------------------------------------------------*/
#include "dbm_multiply_cpu.h"
#include "dbm_hyperparams.h"

#include <assert.h>
#include <stddef.h>
#include <stdint.h>
#include <stdlib.h>

#if defined(__LIBXSMM)
#include <libxsmm.h>
#endif
#if defined(__LIBXS)
#include <libxs/libxs_gemm.h>
#include <libxs/libxs_perm.h>
#endif

/*******************************************************************************
 * \brief Prototype for BLAS dgemm.
 * \author Ole Schuett
 ******************************************************************************/
void dgemm_(const char *transa, const char *transb, const int *m, const int *n,
            const int *k, const double *alpha, const double *a, const int *lda,
            const double *b, const int *ldb, const double *beta, double *c,
            const int *ldc);

/*******************************************************************************
 * \brief Private convenient wrapper to hide Fortran nature of dgemm_.
 * \author Ole Schuett
 ******************************************************************************/
static inline void dbm_dgemm(const char transa, const char transb, const int m,
                             const int n, const int k, const double alpha,
                             const double *a, const int lda, const double *b,
                             const int ldb, const double beta, double *c,
                             const int ldc) {
  dgemm_(&transa, &transb, &m, &n, &k, &alpha, a, &lda, b, &ldb, &beta, c,
         &ldc);
}

/*******************************************************************************
 * \brief Private hash function based on Szudzik's elegant pairing.
 *        Using unsigned int to return a positive number even after overflow.
 *        https://en.wikipedia.org/wiki/Pairing_function#Other_pairing_functions
 *        https://stackoverflow.com/a/13871379
 *        http://szudzik.com/ElegantPairing.pdf
 * \author Ole Schuett
 ******************************************************************************/
static inline unsigned int hash(const dbm_task_t task) {
  const unsigned int m = task.m, n = task.n, k = task.k;
  const unsigned int mn = (m >= n) ? m * m + m + n : m + n * n;
  const unsigned int mnk = (mn >= k) ? mn * mn + mn + k : mn + k * k;
  return mnk;
}

/*******************************************************************************
 * \brief Private routine for mapping a task to its bucket (by shape).
 * \author Hans Pabst
 ******************************************************************************/
static inline int task_bucket(const dbm_task_t task) {
  return (int)(hash(task) % DBM_BATCH_NUM_BUCKETS);
}

/*******************************************************************************
 * \brief Internal routine for ordering the tasks of a batch (exactly by C,
 *        approximately by shape).
 * \author Hans Pabst
 ******************************************************************************/
void dbm_multiply_cpu_task_order(const int ntasks,
                                 const dbm_task_t batch[ntasks],
                                 const int order_kind, int order[ntasks]) {
  if (DBM_TASK_ORDER_C == order_kind) {
    // Exact grouping of tasks sharing a C-block, which lets a kernel
    // accumulate such tasks before writing the C-block once.
    int *const keys = malloc(ntasks * sizeof(int));
    assert(NULL != keys || 0 >= ntasks);
    for (int itask = 0; itask < ntasks; ++itask) {
      order[itask] = itask;
      keys[itask] = batch[itask].offset_c;
    }
#if defined(__LIBXS)
    libxs_sort(order, ntasks, sizeof(int), libxs_cmp_i32_idx, keys);
#endif // order as generated otherwise (only requested along with LIBXS)
    free(keys);
  } else { // approximate grouping by shape
    int buckets[DBM_BATCH_NUM_BUCKETS] = {0};
    for (int itask = 0; itask < ntasks; ++itask) {
      ++buckets[task_bucket(batch[itask])];
    }
    for (int i = 1; i < DBM_BATCH_NUM_BUCKETS; ++i) {
      buckets[i] += buckets[i - 1];
    }
    assert(0 >= ntasks || buckets[DBM_BATCH_NUM_BUCKETS - 1] == ntasks);
    for (int itask = 0; itask < ntasks; ++itask) {
      const int i = task_bucket(batch[itask]);
      --buckets[i];
      order[buckets[i]] = itask;
    }
  }
}

/*******************************************************************************
 * \brief Internal routine for executing the tasks in given batch on the CPU.
 * \author Ole Schuett
 ******************************************************************************/
void dbm_multiply_cpu_process_batch(int ntasks, const dbm_task_t batch[ntasks],
                                    double alpha, const dbm_pack_t *pack_a,
                                    const dbm_pack_t *pack_b,
                                    dbm_shard_t *shard_c, int options) {
  if (0 >= ntasks) { // nothing to do
    return;
  }
  dbm_shard_allocate_promised_blocks(shard_c);
  dbm_multiply_cpu_process_tasks(ntasks, batch, alpha, pack_a, pack_b,
                                 shard_c->data, options);
}

/*******************************************************************************
 * \brief Internal routine telling whether the CPU runs generated kernels, i.e.,
 *        rivals a GPU, for tasks up to the given maxima (all zero: any task).
 *        What holds for the maxima holds for every smaller task.
 * \author Hans Pabst
 ******************************************************************************/
bool dbm_multiply_cpu_generated(int max_m, int max_n, int max_k, double alpha,
                                int options) {
  bool result = false;
#if defined(__LIBXS)
  if (0 == (DBM_MULTIPLY_BLAS_LIBRARY & options)) {
    libxs_gemm_backend_t backend;
    libxs_gemm_backend_init(&backend);
    if (0 < max_m && 0 < max_n && 0 < max_k) { // as dispatched per task
      const libxs_gemm_shape_t shape = {.datatype = LIBXS_DATATYPE_F64,
                                        .transa = 'N',
                                        .transb = 'T',
                                        .m = max_m,
                                        .n = max_n,
                                        .k = max_k,
                                        .lda = max_m,
                                        .ldb = max_n,
                                        .ldc = max_m,
                                        .alpha = alpha,
                                        .beta = 1.0};
      result =
          (LIBXS_GEMM_KIND_JIT == libxs_gemm_backend_kind(&backend, &shape));
    } else {
      result = (LIBXS_GEMM_KIND_JIT == libxs_gemm_backend_kind(&backend, NULL));
    }
  }
#else
  (void)max_m; // mark used
  (void)max_n;
  (void)max_k;
  (void)alpha;
  (void)options;
#endif
  return result;
}

/*******************************************************************************
 * \brief Internal routine for executing the tasks in given batch on the CPU,
 *        which accumulates into data_c holding every block of the batch.
 * \author Ole Schuett and Hans Pabst
 ******************************************************************************/
void dbm_multiply_cpu_process_tasks(int ntasks, const dbm_task_t batch[ntasks],
                                    double alpha, const dbm_pack_t *pack_a,
                                    const dbm_pack_t *pack_b, double *data_c,
                                    int options) {
  if (0 >= ntasks) { // nothing to do
    return;
  }

  int batch_order[ntasks];
  if (DBM_MULTIPLY_TASK_REORDER & options) {
    dbm_multiply_cpu_task_order(ntasks, batch, DBM_TASK_ORDER_SHAPE,
                                batch_order);
  } else {
    for (int itask = 0; itask < ntasks; ++itask) {
      batch_order[itask] = itask;
    }
  }

#if defined(__LIBXS)
  const libxs_gemm_config_t *gemm_config = NULL;
  int kernel_m = 0, kernel_n = 0, kernel_k = 0;
#endif

  // Loop over tasks.
  dbm_task_t task_next = batch[batch_order[0]];
  for (int itask = 0; itask < ntasks; ++itask) {
    const dbm_task_t task = task_next;
    task_next = batch[batch_order[(itask + 1) < ntasks ? (itask + 1) : itask]];

#if defined(__LIBXS)
    if (0 == (DBM_MULTIPLY_BLAS_LIBRARY & options) &&
        (task.m != kernel_m || task.n != kernel_n || task.k != kernel_k)) {
      const double beta = 1.0;
      gemm_config = libxs_gemm_dispatch(LIBXS_DATATYPE_F64, 'N', 'T', task.m,
                                        task.n, task.k, task.m, task.n, task.m,
                                        &alpha, &beta, NULL);
      kernel_m = task.m;
      kernel_n = task.n;
      kernel_k = task.k;
    }
#endif

    double *const data_a = pack_a->data + task.offset_a;
    double *const data_b = pack_b->data + task.offset_b;
    double *const task_c = data_c + task.offset_c;

#if defined(__LIBXS)
    if (NULL != gemm_config) {
      libxs_gemm_call(gemm_config, data_a, data_b, task_c);
    } else
#endif
    {
      dbm_dgemm('N', 'T', task.m, task.n, task.k, alpha, data_a, task.m, data_b,
                task.n, 1.0, task_c, task.m);
    }
  }
}

// EOF
