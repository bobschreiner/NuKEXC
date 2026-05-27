/*
 *    NuKEXC -- Numerical Kokkos Enhanced Exchange Correlation Integrator
 *    Copyright (C) 2026 Bob Schreiner
 *
 *    This program is free software: you can redistribute it and/or modify
 *    it under the terms of the GNU General Public License as published by
 *    the Free Software Foundation, either version 3 of the License, or
 *    (at your option) any later version.
 *
 *    This program is distributed in the hope that it will be useful,
 *    but WITHOUT ANY WARRANTY; without even the implied warranty of
 *    MERCHANTABILITY or FITNESS FOR A PARTICULAR PURPOSE.  See the
 *    GNU General Public License for more details.
 *
 *    You should have received a copy of the GNU General Public License
 *    along with this program.  If not, see <https://www.gnu.org/licenses/>.
 *
 *
 */

#pragma once
#include "molecule.hpp"
#include "nukexc_config.hpp"
#include "octree.hpp"
#include "partitioning.hpp"
#include "stobasis.hpp"

#include <KokkosBatched_Copy_Decl.hpp>
#include <KokkosBatched_Copy_Impl.hpp>
#include <KokkosBatched_Dot.hpp>
#include <KokkosBatched_Gemm_Decl.hpp>
#include <KokkosBatched_Gemm_Team_Impl.hpp>
#include <KokkosBatched_Util.hpp>

#include <KokkosBlas3_gemm.hpp>
#include <Kokkos_Core_fwd.hpp>
#include <Kokkos_MathematicalFunctions.hpp>
#include <Kokkos_Pair.hpp>
#include <impl/Kokkos_Profiling.hpp>
#include <stdexcept>

namespace NuKEXC {
// A helper to determine batch size based on available memory or a fixed
// constant
const size_t CHUNK_SIZE = 50000;

DeviceView2DLeft
overlap_integral(STOBasisSet &basis, Kokkos::View<Point *> quadrature_points,
                 Kokkos::View<double *, ExecSpace> quadrature_weights) {

  int N = basis.nbf();
  int total_quad_points = quadrature_points.extent(0);

  DeviceView2DLeft overlap_matrix("Overlap matrix", N, N);
  // Pre-allocate ALL buffers — two sets, one per stream
  DeviceView2DLeft col_a("col_a", N, CHUNK_SIZE);
  DeviceView2DLeft col_b("col_b", N, CHUNK_SIZE);
  DeviceView2DLeft wt_a("wt_a", N, CHUNK_SIZE);
  DeviceView2DLeft wt_b("wt_b", N, CHUNK_SIZE);

  ExecSpace space_a, space_b;

  for (size_t start = 0; start < total_quad_points; start += CHUNK_SIZE) {
    int current_batch_size = std::min(CHUNK_SIZE, total_quad_points - start);
    bool even = (start / CHUNK_SIZE) % 2 == 0;

    auto &col_cur = even ? col_a : col_b;
    auto &wt_cur = even ? wt_a : wt_b;
    auto &space_cur = even ? space_a : space_b;
    auto &space_prev = even ? space_b : space_a;

    auto batch_pts = Kokkos::subview(
        quadrature_points, std::make_pair(start, start + current_batch_size));
    auto batch_wts = Kokkos::subview(
        quadrature_weights, std::make_pair(start, start + current_batch_size));
    auto col_view = Kokkos::subview(col_cur, Kokkos::ALL,
                                    std::make_pair(0, current_batch_size));
    auto wt_view = Kokkos::subview(wt_cur, Kokkos::ALL,
                                   std::make_pair(0, current_batch_size));

    // Collocation on space_cur — can overlap with GEMM still running
    // on space_prev from the last iteration
    fill_collocation(space_cur, basis, batch_pts, col_view); // no alloc

    Kokkos::parallel_for(
        "Scale",
        Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>(
            space_cur, {0, 0}, {N, current_batch_size}),
        KOKKOS_LAMBDA(int i, int g) {
          wt_view(i, g) = batch_wts(g) * col_view(i, g);
        });

    // CRITICAL: wait for previous GEMM to finish before starting next one
    // They cannot run concurrently — both write to overlap_matrix
    space_prev.fence();

    KokkosBlas::gemm(space_cur, "N", "T", 1.0, wt_view, col_view, 1.0,
                     overlap_matrix);
  }

  space_a.fence();
  space_b.fence();
  return overlap_matrix;
}

DeviceView2DLeft
diag_overlap_integral(STOBasisSet &basis,
                      Kokkos::View<Point *> quadrature_points,
                      Kokkos::View<double *> quadrature_weights) {

  size_t N = basis.nbf();
  size_t nquad_points = quadrature_points.extent(0);

  DeviceView2DLeft diag_overlap_matrix("Overlap matrix", N, N);
  DeviceView2DLeft collocation_values("Collocation values", N, nquad_points);
  ExecSpace space;

  fill_collocation(space, basis, quadrature_points, collocation_values);
  // Can be replaced by Kokkos kernel later

  Kokkos::parallel_for(
      "Compute diag{S}", N, KOKKOS_LAMBDA(const int &i) {
        for (int g = 0; g < nquad_points; ++g) {
          diag_overlap_matrix(i, i) += quadrature_weights(g) *
                                       collocation_values(i, g) *
                                       collocation_values(i, g);
        }
      });
  return diag_overlap_matrix;
}

DeviceView2DLeft nuclear_potential_integral(
    STOBasisSet &basis, Kokkos::View<Point *> quadrature_points,
    Kokkos::View<double *> quadrature_weights,
    Kokkos::View<Point *> atom_centers, Kokkos::View<unsigned *> Z) {

  int N = basis.nbf();
  int total_quad_points = quadrature_points.extent(0);

  DeviceView2DLeft V_n("Nuclear potential matrix", N, N);

  // Pre-allocate ALL buffers — two sets, one per stream
  DeviceView2DLeft col_a("col_a", N, CHUNK_SIZE);
  DeviceView2DLeft col_b("col_b", N, CHUNK_SIZE);
  DeviceView2DLeft wt_a("wt_a", N, CHUNK_SIZE);
  DeviceView2DLeft wt_b("wt_b", N, CHUNK_SIZE);

  ExecSpace space_a, space_b;

  for (size_t start = 0; start < total_quad_points; start += CHUNK_SIZE) {
    int current_batch_size = std::min(CHUNK_SIZE, total_quad_points - start);
    bool even = (start / CHUNK_SIZE) % 2 == 0;

    auto &col_cur = even ? col_a : col_b;
    auto &wt_cur = even ? wt_a : wt_b;
    auto &space_cur = even ? space_a : space_b;
    auto &space_prev = even ? space_b : space_a;

    auto batch_pts = Kokkos::subview(
        quadrature_points, std::make_pair(start, start + current_batch_size));
    auto batch_wts = Kokkos::subview(
        quadrature_weights, std::make_pair(start, start + current_batch_size));
    auto col_view = Kokkos::subview(col_cur, Kokkos::ALL,
                                    std::make_pair(0, current_batch_size));
    auto wt_view = Kokkos::subview(wt_cur, Kokkos::ALL,
                                   std::make_pair(0, current_batch_size));
    // Collocation on space_cur — can overlap with GEMM still running
    // on space_prev from the last iteration
    fill_collocation(space_cur, basis, batch_pts, col_view); // no alloc
    Kokkos::deep_copy(space_cur, wt_view, 0.0); // zero out previous batch
    Kokkos::parallel_for(
        "Scale (nuclear potential)",
        Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>(
            space_cur, {0, 0}, {N, current_batch_size}),
        KOKKOS_LAMBDA(int i, int g) {
          for (unsigned int k = 0; k < atom_centers.extent(0); ++k) {
            double r = dist(batch_pts(g), atom_centers(k)) + epsilon_shift;

            wt_view(i, g) -= (Z(k) / r) * batch_wts(g) * col_view(i, g);
          }
        });

    // CRITICAL: wait for previous GEMM to finish before starting next one
    // They cannot run concurrently — both write to overlap_matrix
    space_prev.fence();

    KokkosBlas::gemm(space_cur, "N", "T", 1.0, wt_view, col_view, 1.0, V_n);
  }
  space_a.fence();
  space_b.fence();
  return V_n;
}

DeviceView2DLeft
kinetic_integral(STOBasisSet &basis,
                 Kokkos::View<Point *, ExecSpace> quadrature_points,
                 Kokkos::View<double *, ExecSpace> quadrature_weights) {

  int N = basis.nbf();
  int total_quad_points = quadrature_points.extent(0);

  DeviceView2DLeft kinetic_matrix("Kinetic matrix", N, N);

  // Pre-allocate double buffers — grad collocation has 3 components
  Kokkos::View<double **[3], ExecSpace> grad_a("grad_a", N, CHUNK_SIZE);
  Kokkos::View<double **[3], ExecSpace> grad_b("grad_b", N, CHUNK_SIZE);

  // Weighted gradient buffers — one per spatial direction per stream
  DeviceView2DLeft Gx_a("Gx_a", N, CHUNK_SIZE), Gx_b("Gx_b", N, CHUNK_SIZE);
  DeviceView2DLeft Gy_a("Gy_a", N, CHUNK_SIZE), Gy_b("Gy_b", N, CHUNK_SIZE);
  DeviceView2DLeft Gz_a("Gz_a", N, CHUNK_SIZE), Gz_b("Gz_b", N, CHUNK_SIZE);

  ExecSpace space_a, space_b;

  for (size_t start = 0; start < total_quad_points; start += CHUNK_SIZE) {
    int cur = std::min(CHUNK_SIZE, total_quad_points - start);
    bool even = (start / CHUNK_SIZE) % 2 == 0;

    auto &grad_cur = even ? grad_a : grad_b;
    auto &Gx_cur = even ? Gx_a : Gx_b;
    auto &Gy_cur = even ? Gy_a : Gy_b;
    auto &Gz_cur = even ? Gz_a : Gz_b;
    auto &space_cur = even ? space_a : space_b;
    auto &space_prev = even ? space_b : space_a;

    auto batch_pts =
        Kokkos::subview(quadrature_points, std::make_pair(start, start + cur));
    auto batch_wts =
        Kokkos::subview(quadrature_weights, std::make_pair(start, start + cur));

    // Subviews into current chunk size
    auto grad_view = Kokkos::subview(grad_cur, Kokkos::ALL,
                                     std::make_pair(0, cur), Kokkos::ALL);
    auto Gx_view = Kokkos::subview(Gx_cur, Kokkos::ALL, std::make_pair(0, cur));
    auto Gy_view = Kokkos::subview(Gy_cur, Kokkos::ALL, std::make_pair(0, cur));
    auto Gz_view = Kokkos::subview(Gz_cur, Kokkos::ALL, std::make_pair(0, cur));

    // Fill grad collocation on space_cur — overlaps with GEMM on space_prev
    fill_grad_collocation(space_cur, basis, batch_pts, grad_view);

    // Weight the gradients: G{xyz}(i,g) = grad(i,g,d) * sqrt(w(g))
    Kokkos::parallel_for(
        "Weight gradients",
        Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>(space_cur, {0, 0},
                                                          {N, cur}),
        KOKKOS_LAMBDA(int i, int g) {
          double wf = Kokkos::sqrt(batch_wts(g));
          Gx_view(i, g) = grad_view(i, g, 0) * wf;
          Gy_view(i, g) = grad_view(i, g, 1) * wf;
          Gz_view(i, g) = grad_view(i, g, 2) * wf;
        });

    // Wait for previous iteration's GEMMs before writing to kinetic_matrix
    space_prev.fence();

    // Three GEMMs accumulate into kinetic_matrix sequentially on space_cur
    // First batch uses beta=1.0 to accumulate across chunks
    KokkosBlas::gemm(space_cur, "N", "T", 0.5, Gx_view, Gx_view, 1.0,
                     kinetic_matrix);
    KokkosBlas::gemm(space_cur, "N", "T", 0.5, Gy_view, Gy_view, 1.0,
                     kinetic_matrix);
    KokkosBlas::gemm(space_cur, "N", "T", 0.5, Gz_view, Gz_view, 1.0,
                     kinetic_matrix);
  }

  space_a.fence();
  space_b.fence();
  return kinetic_matrix;
}

struct CoreHamiltonianResult {
  DeviceView2DLeft overlap;
  DeviceView2DLeft kinetic;
  DeviceView2DLeft nuclear;
  DeviceView2DLeft hamiltonian; // T + V_n
};

CoreHamiltonianResult compute_core_hamiltonian(const STOBasisSet &basis,
                                               const FlatGrid &grid) {

  int N = basis.nbf();
  auto quadrature_points = grid.quad_points;
  auto quadrature_weights = grid.weights;
  auto Z = grid.Z;
  auto atom_centers = grid.atom_centers;

  int total_quad_points = quadrature_points.extent(0);

  CoreHamiltonianResult result;
  result.overlap = DeviceView2DLeft("Overlap matrix", N, N);
  result.kinetic = DeviceView2DLeft("Kinetic matrix", N, N);
  result.nuclear = DeviceView2DLeft("Nuclear potential matrix", N, N);
  result.hamiltonian = DeviceView2DLeft("Core Hamiltonian", N, N);

  // Single set of double buffers shared across all three integrals
  DeviceView2DLeft col_a("col_a", N, CHUNK_SIZE);
  DeviceView2DLeft col_b("col_b", N, CHUNK_SIZE);
  DeviceView2DLeft wt_overlap_a("wt_overlap_a", N, CHUNK_SIZE);
  DeviceView2DLeft wt_overlap_b("wt_overlap_b", N, CHUNK_SIZE);
  DeviceView2DLeft wt_nuclear_a("wt_nuclear_a", N, CHUNK_SIZE);
  DeviceView2DLeft wt_nuclear_b("wt_nuclear_b", N, CHUNK_SIZE);

  DeviceView2DLeft Gx_a("Gx_a", N, CHUNK_SIZE), Gx_b("Gx_b", N, CHUNK_SIZE);
  DeviceView2DLeft Gy_a("Gy_a", N, CHUNK_SIZE), Gy_b("Gy_b", N, CHUNK_SIZE);
  DeviceView2DLeft Gz_a("Gz_a", N, CHUNK_SIZE), Gz_b("Gz_b", N, CHUNK_SIZE);

  ExecSpace space_a, space_b;

  for (size_t start = 0; start < total_quad_points; start += CHUNK_SIZE) {
    int current_batch_size = std::min(CHUNK_SIZE, total_quad_points - start);
    bool even = (start / CHUNK_SIZE) % 2 == 0;

    auto &col_cur = even ? col_a : col_b;
    auto &wt_ov_cur = even ? wt_overlap_a : wt_overlap_b;
    auto &wt_nuc_cur = even ? wt_nuclear_a : wt_nuclear_b;
    auto &Gx_cur = even ? Gx_a : Gx_b;
    auto &Gy_cur = even ? Gy_a : Gy_b;
    auto &Gz_cur = even ? Gz_a : Gz_b;
    auto &space_cur = even ? space_a : space_b;
    auto &space_prev = even ? space_b : space_a;

    auto batch_pts = Kokkos::subview(
        quadrature_points, std::make_pair(start, start + current_batch_size));
    auto batch_wts = Kokkos::subview(
        quadrature_weights, std::make_pair(start, start + current_batch_size));

    auto overlap_view = Kokkos::subview(wt_ov_cur, Kokkos::ALL,
                                        std::make_pair(0, current_batch_size));
    auto nuclear_view = Kokkos::subview(wt_nuc_cur, Kokkos::ALL,
                                        std::make_pair(0, current_batch_size));
    auto Gx_view = Kokkos::subview(Gx_cur, Kokkos::ALL,
                                   std::make_pair(0, current_batch_size));
    auto Gy_view = Kokkos::subview(Gy_cur, Kokkos::ALL,
                                   std::make_pair(0, current_batch_size));
    auto Gz_view = Kokkos::subview(Gz_cur, Kokkos::ALL,
                                   std::make_pair(0, current_batch_size));

    Kokkos::TeamPolicy<ExecSpace> policy(space_cur, current_batch_size,
                                         Kokkos::AUTO());
    using member_type = Kokkos::TeamPolicy<ExecSpace>::member_type;

    // Single fused kernel: compute overlap weights, nuclear weights,
    // and gradient weights all in one pass over (i, g)
    Kokkos::parallel_for(
        "Fused scale", policy, KOKKOS_LAMBDA(member_type team_member) {
          const int g = team_member.league_rank();
          const Point local_pt = batch_pts(g);

          Kokkos::parallel_for(
              Kokkos::TeamVectorRange(team_member, N), [=](const int i) {
                ScratchBasisParams basis_i{basis.zeta(i), basis.norm(i),
                                           basis.O(i),    basis.n(i),
                                           basis.l(i),    basis.m(i)};
                basis_eval_with_grad(basis_i, local_pt, overlap_view(i, g),
                                     Gx_view(i, g), Gy_view(i, g),
                                     Gz_view(i, g));
              });

          double v_nuc = 0.0;
          Kokkos::parallel_reduce(
              Kokkos::TeamThreadRange(team_member, atom_centers.extent(0)),
              [=](const int k, double &local_v) {
                double r = dist(local_pt, atom_centers(k)) + epsilon_shift;
                local_v += double(Z(k)) / r;
              },
              v_nuc);
          v_nuc = Kokkos::sqrt(v_nuc);

          const double wf = Kokkos::sqrt(batch_wts(g));
          Kokkos::parallel_for(Kokkos::TeamVectorRange(team_member, N),
                               [=](const int i) {
                                 double ov_wf = overlap_view(i, g) * wf;
                                 // Overlap weight
                                 overlap_view(i, g) = ov_wf;

                                 // Nuclear weight — accumulate over atoms
                                 nuclear_view(i, g) = ov_wf * v_nuc;

                                 // Gradient weights
                                 Gx_view(i, g) *= wf;
                                 Gy_view(i, g) *= wf;
                                 Gz_view(i, g) *= wf;
                               });
        });

    // Serialise GEMMs against previous iteration
    space_prev.fence();

    // Overlap: S += wt_ov * col^T
    KokkosBlas::gemm(space_cur, "N", "T", 1.0, overlap_view, overlap_view, 1.0,
                     result.overlap);

    // Nuclear: V += wt_nuc * col^T
    KokkosBlas::gemm(space_cur, "N", "T", -1.0, nuclear_view, nuclear_view, 1.0,
                     result.nuclear);

    // Kinetic: T += 0.5 * G{xyz} * G{xyz}^T
    KokkosBlas::gemm(space_cur, "N", "T", 0.5, Gx_view, Gx_view, 1.0,
                     result.kinetic);
    KokkosBlas::gemm(space_cur, "N", "T", 0.5, Gy_view, Gy_view, 1.0,
                     result.kinetic);
    KokkosBlas::gemm(space_cur, "N", "T", 0.5, Gz_view, Gz_view, 1.0,
                     result.kinetic);
  }

  space_a.fence();
  space_b.fence();

  // Form H = T + V_n
  int total = N * N;
  auto T = result.kinetic;
  auto V = result.nuclear;
  auto H = result.hamiltonian;
  Kokkos::parallel_for(
      "Form core Hamiltonian",
      Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>({0, 0}, {N, N}),
      KOKKOS_LAMBDA(int i, int j) { H(i, j) = T(i, j) + V(i, j); });

  return result;
}

struct CoreHamiltonianReducer {
  double s = 0.0, v = 0.0, t = 0.0;

  KOKKOS_INLINE_FUNCTION
  CoreHamiltonianReducer &operator+=(const CoreHamiltonianReducer &rhs) {
    s += rhs.s;
    v += rhs.v;
    t += rhs.t;
    return *this;
  }

  KOKKOS_INLINE_FUNCTION
  CoreHamiltonianReducer operator+(const CoreHamiltonianReducer &rhs) const {
    return {s + rhs.s, v + rhs.v, t + rhs.t};
  }
  KOKKOS_INLINE_FUNCTION
  void join(CoreHamiltonianReducer &dst, const CoreHamiltonianReducer &src) {
    dst.s += src.s;
    dst.v += src.v;
    dst.t += src.t;
  }

  KOKKOS_INLINE_FUNCTION static void init(CoreHamiltonianReducer &val) {
    val.s = 0.0;
    val.v = 0.0;
    val.t = 0.0;
  }
};

CoreHamiltonianResult compute_core_hamiltonian_screened(
    const STOBasisSet &basis, const FlatGrid &grid, const NeighborList &nl) {

  int N = basis.nbf();
  auto Z = grid.Z;
  auto atom_centers = grid.atom_centers;

  const int max_points_per_box = nl.max_points_per_box;
  const int total_points = nl.total_points;
  const int num_boxes = nl.offsets.extent(0) - 1;

  CoreHamiltonianResult result;
  result.overlap = DeviceView2DLeft("Overlap matrix", N, N);
  result.kinetic = DeviceView2DLeft("Kinetic matrix", N, N);
  result.nuclear = DeviceView2DLeft("Nuclear potential matrix", N, N);
  result.hamiltonian = DeviceView2DLeft("Core Hamiltonian", N, N);

  Kokkos::TeamPolicy<ExecSpace> policy(num_boxes, Kokkos::AUTO());
  using member_type = Kokkos::TeamPolicy<ExecSpace>::member_type;

  Kokkos::parallel_for(
      "Compute Core Hamiltonian Screened", policy,
      KOKKOS_LAMBDA(const member_type &team_member) {
        const int box_idx = team_member.league_rank();

        // Compute number of points per box
        const int start_points = box_idx * max_points_per_box;
        const int end_points =
            Kokkos::min(start_points + max_points_per_box, total_points);
        const int num_points = end_points - start_points;

        // Compute number of neighbors per box
        const int start_neighbors = nl.offsets(box_idx);
        const int end_neighbors = nl.offsets(box_idx + 1);
        const int num_neighbors = end_neighbors - start_neighbors;

        Kokkos::parallel_for(
            Kokkos::TeamThreadMDRange(team_member, num_neighbors,
                                      num_neighbors),
            [=](const int local_i, const int local_j) {
              const int global_i = nl.neighbors(start_neighbors + local_i);
              const int global_j = nl.neighbors(start_neighbors + local_j);

              if (global_i < global_j)
                return;

              ScratchBasisParams local_basis_i{
                  basis.zeta(global_i), basis.norm(global_i),
                  basis.O(global_i),    basis.n(global_i),
                  basis.l(global_i),    basis.m(global_i)};

              ScratchBasisParams local_basis_j{
                  basis.zeta(global_j), basis.norm(global_j),
                  basis.O(global_j),    basis.n(global_j),
                  basis.l(global_j),    basis.m(global_j)};

              double total_s = 0.0;
              double total_t = 0.0;
              double total_v = 0.0;

              for (int local_g = 0; local_g < num_points; ++local_g) {

                const int global_g = max_points_per_box * box_idx + local_g;
                double w_g = grid.weights(global_g);
                Point quad_point_g = grid.quad_points(global_g);
                double v_g = 0.0;
                for (int k = 0; k < grid.atom_centers.extent(0); ++k) {
                  double r = dist(grid.atom_centers(k), quad_point_g);
                  v_g -= grid.Z(k) / r;
                }

                double basis_val_i;
                double basis_gx_i;
                double basis_gy_i;
                double basis_gz_i;

                double basis_val_j;
                double basis_gx_j;
                double basis_gy_j;
                double basis_gz_j;

                basis_eval_with_grad(local_basis_j, quad_point_g, basis_val_j,
                                     basis_gx_j, basis_gy_j, basis_gz_j);
                basis_eval_with_grad(local_basis_i, quad_point_g, basis_val_i,
                                     basis_gx_i, basis_gy_i, basis_gz_i);

                const double local_s = w_g * basis_val_i * basis_val_j;
                total_s += local_s;
                total_t += 0.5 * w_g *
                           (basis_gx_i * basis_gx_j + basis_gy_i * basis_gy_j +
                            basis_gz_i * basis_gz_j);
                total_v += v_g * local_s;
              }

              Kokkos::atomic_add(&result.overlap(global_i, global_j), total_s);
              Kokkos::atomic_add(&result.kinetic(global_i, global_j), total_t);
              Kokkos::atomic_add(&result.nuclear(global_i, global_j), total_v);
              if (global_i != global_j) {
                Kokkos::atomic_add(&result.overlap(global_j, global_i),
                                   total_s);
                Kokkos::atomic_add(&result.kinetic(global_j, global_i),
                                   total_t);
                Kokkos::atomic_add(&result.nuclear(global_j, global_i),
                                   total_v);
              }
            });
      });

  ExecSpace().fence();
  Kokkos::parallel_for(
      "Compute Core Hamiltonian Matrix",
      Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>({0, 0}, {N, N}),
      KOKKOS_LAMBDA(const int i, const int j) {
        result.hamiltonian(i, j) = result.kinetic(i, j) + result.nuclear(i, j);
      });

  Kokkos::fence();
  return result;
}

CoreHamiltonianResult compute_core_hamiltonian_screened_scratch(
    const STOBasisSet &basis, const FlatGrid &grid, const NeighborList &nl) {
  int N = basis.nbf();
  auto Z = grid.Z;
  auto atom_centers = grid.atom_centers;

  const int max_points_per_box = nl.max_points_per_box;
  const int total_points = nl.total_points;
  const int num_boxes = nl.offsets.extent(0) - 1;

  CoreHamiltonianResult result;
  result.overlap = DeviceView2DLeft("Overlap matrix", N, N);
  result.kinetic = DeviceView2DLeft("Kinetic matrix", N, N);
  result.nuclear = DeviceView2DLeft("Nuclear potential matrix", N, N);
  result.hamiltonian = DeviceView2DLeft("Core Hamiltonian", N, N);

  // Define helpers for scratch space access
  typedef ExecSpace::scratch_memory_space ScratchSpace;

  typedef Kokkos::View<ScratchBasisParams *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_basis;

  typedef Kokkos::View<double *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_double;

  typedef Kokkos::View<Point *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_points;

  using Bounds = Kokkos::LaunchBounds<256, 4>;
  Kokkos::TeamPolicy<ExecSpace, Bounds> policy(num_boxes, Kokkos::AUTO());
  using member_type = Kokkos::TeamPolicy<ExecSpace>::member_type;

  int scratch_size = shared_view_double::shmem_size(max_points_per_box) +
                     shared_view_double::shmem_size(max_points_per_box) +
                     shared_view_points::shmem_size(max_points_per_box);

  policy.set_scratch_size(0, Kokkos::PerTeam(scratch_size));

  Kokkos::parallel_for(
      "Compute Core Hamiltonian Screened", policy,
      KOKKOS_LAMBDA(const member_type &team_member) {
        const int box_idx = team_member.league_rank();

        // Compute number of points per box
        const int start_points = box_idx * max_points_per_box;
        const int end_points =
            Kokkos::min(start_points + max_points_per_box, total_points);
        const int num_points = end_points - start_points;

        // Compute number of neighbors per box
        const int start_neighbors = nl.offsets(box_idx);
        const int end_neighbors = nl.offsets(box_idx + 1);
        const int num_neighbors = end_neighbors - start_neighbors;

        shared_view_double weights_scratch(team_member.team_scratch(0),
                                           num_points);
        shared_view_double v_scratch(team_member.team_scratch(0), num_points);

        shared_view_points points_scratch(team_member.team_scratch(0),
                                          num_points);

        // Fill the scratch
        Kokkos::parallel_for(
            Kokkos::TeamVectorRange(team_member, num_points),
            [=](const int local_g) {
              const int global_g = start_points + local_g;
              weights_scratch(local_g) = grid.weights(global_g);
              points_scratch(local_g) = grid.quad_points(global_g);
              v_scratch(local_g) = 0.0;
              for (unsigned k = 0; k < atom_centers.extent(0); ++k) {
                double r = dist(points_scratch(local_g), atom_centers(k)) +
                           epsilon_shift;
                v_scratch(local_g) -= double(Z(k)) / r;
              }
            });

        team_member.team_barrier();
        Kokkos::parallel_for(
            Kokkos::TeamThreadMDRange(team_member, num_neighbors,
                                      num_neighbors),
            [=](const int local_i, const int local_j) {
              const int global_i = nl.neighbors(start_neighbors + local_i);
              const int global_j = nl.neighbors(start_neighbors + local_j);

              if (global_i < global_j)
                return;

              ScratchBasisParams local_basis_i{
                  basis.zeta(global_i), basis.norm(global_i),
                  basis.O(global_i),    basis.n(global_i),
                  basis.l(global_i),    basis.m(global_i)};

              ScratchBasisParams local_basis_j{
                  basis.zeta(global_j), basis.norm(global_j),
                  basis.O(global_j),    basis.n(global_j),
                  basis.l(global_j),    basis.m(global_j)};

              double total_s = 0.0;
              double total_t = 0.0;
              double total_v = 0.0;

              Kokkos::parallel_reduce(
                  Kokkos::ThreadVectorRange(team_member, num_points),
                  [=](const int local_g, double &update_s, double &update_t,
                      double &update_v) {
                    double basis_val_i;
                    double basis_gx_i;
                    double basis_gy_i;
                    double basis_gz_i;

                    double basis_val_j;
                    double basis_gx_j;
                    double basis_gy_j;
                    double basis_gz_j;

                    basis_eval_with_grad(local_basis_j, points_scratch(local_g),
                                         basis_val_j, basis_gx_j, basis_gy_j,
                                         basis_gz_j);
                    basis_eval_with_grad(local_basis_i, points_scratch(local_g),
                                         basis_val_i, basis_gx_i, basis_gy_i,
                                         basis_gz_i);

                    const double local_s =
                        weights_scratch(local_g) * basis_val_i * basis_val_j;

                    update_s += local_s;
                    update_t +=
                        0.5 * weights_scratch(local_g) *
                        (basis_gx_i * basis_gx_j + basis_gy_i * basis_gy_j +
                         basis_gz_i * basis_gz_j);
                    update_v += v_scratch(local_g) * local_s;
                  },
                  total_s, total_t, total_v);

              Kokkos::atomic_add(&result.overlap(global_i, global_j), total_s);
              Kokkos::atomic_add(&result.kinetic(global_i, global_j), total_t);
              Kokkos::atomic_add(&result.nuclear(global_i, global_j), total_v);
              if (global_i != global_j) {
                Kokkos::atomic_add(&result.overlap(global_j, global_i),
                                   total_s);
                Kokkos::atomic_add(&result.kinetic(global_j, global_i),
                                   total_t);
                Kokkos::atomic_add(&result.nuclear(global_j, global_i),
                                   total_v);
              }
            });
      });

  ExecSpace().fence();
  Kokkos::parallel_for(
      "Compute Core Hamiltonian Matrix",
      Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>({0, 0}, {N, N}),
      KOKKOS_LAMBDA(const int i, const int j) {
        result.hamiltonian(i, j) = result.kinetic(i, j) + result.nuclear(i, j);
      });

  Kokkos::fence();
  return result;
}

template <int MAX_NEIGHBORS_TILE = 8, int MAX_POINTS_PER_TILE = 16>
CoreHamiltonianResult compute_core_hamiltonian_screened_tiled(
    const STOBasisSet &basis, const FlatGrid &grid, const NeighborList &nl) {

  int N = basis.nbf();
  auto Z = grid.Z;
  auto atom_centers = grid.atom_centers;

  const int max_points_per_box = nl.max_points_per_box;
  const int total_points = nl.total_points;
  const int num_boxes = nl.offsets.extent(0) - 1;

  CoreHamiltonianResult result;
  result.overlap = DeviceView2DLeft("Overlap matrix", N, N);
  result.kinetic = DeviceView2DLeft("Kinetic matrix", N, N);
  result.nuclear = DeviceView2DLeft("Nuclear potential matrix", N, N);
  result.hamiltonian = DeviceView2DLeft("Core Hamiltonian", N, N);

  // Define helpers for scratch space access
  typedef ExecSpace::scratch_memory_space ScratchSpace;

  typedef Kokkos::View<double *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_double;

  typedef Kokkos::View<double **, Kokkos::LayoutRight, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view2d_double;

  typedef Kokkos::View<Point *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_points;

  using Bounds = Kokkos::LaunchBounds<128, 2>;
  int fixed_team_size = 1;
  int fixed_vector_length = 1;
#if defined(KOKKOS_ENABLE_HIP)
  fixed_team_size = 64;
  fixed_vector_length = 1;
#endif
  Kokkos::TeamPolicy<ExecSpace, Bounds> policy(num_boxes, fixed_team_size,
                                               fixed_vector_length);
  using member_type = Kokkos::TeamPolicy<ExecSpace, Bounds>::member_type;

  int scratch_size = 2 * shared_view_double::shmem_size(MAX_POINTS_PER_TILE) +
                     shared_view_points::shmem_size(MAX_POINTS_PER_TILE) +
                     9 * shared_view2d_double::shmem_size(MAX_NEIGHBORS_TILE,
                                                          MAX_POINTS_PER_TILE) +
                     3 * shared_view2d_double::shmem_size(MAX_NEIGHBORS_TILE,
                                                          MAX_NEIGHBORS_TILE);

  policy.set_scratch_size(0, Kokkos::PerTeam(scratch_size));

  std::cout << "------------Allocated "
               "Memory-------------"
            << std::endl;
  std::cout << "Available L0 scratch : " << policy.scratch_size_max(0)
            << std::endl;
  std::cout << "Allocated L0 scratch : " << scratch_size << std::endl;
  std::cout << "------------------------"
               "-----------------"
            << std::endl;

  Kokkos::parallel_for(
      "Compute Core Hamiltonian "
      "Screened",
      policy, KOKKOS_LAMBDA(const member_type &team_member) {
        const int box_idx = team_member.league_rank();

        // Compute number of points
        // per box
        const int start_points = box_idx * max_points_per_box;
        const int end_points =
            Kokkos::min(start_points + max_points_per_box, total_points);
        const int num_points = end_points - start_points;

        // Compute number of
        // neighbors per box
        const int start_neighbors = nl.offsets(box_idx);
        const int end_neighbors = nl.offsets(box_idx + 1);
        const int num_neighbors = end_neighbors - start_neighbors;

        // Compute number of tiles
        const int num_tiles =
            (num_neighbors + MAX_NEIGHBORS_TILE - 1) / MAX_NEIGHBORS_TILE;

        shared_view_double weights_scratch(team_member.team_scratch(0),
                                           MAX_POINTS_PER_TILE);

        shared_view_double v_scratch(team_member.team_scratch(0),
                                     MAX_POINTS_PER_TILE);

        shared_view_points points_scratch(team_member.team_scratch(0),
                                          MAX_POINTS_PER_TILE);

        shared_view2d_double tile_val_i(team_member.team_scratch(0),
                                        MAX_NEIGHBORS_TILE,
                                        MAX_POINTS_PER_TILE);
        shared_view2d_double tile_nuc_i(team_member.team_scratch(0),
                                        MAX_NEIGHBORS_TILE,
                                        MAX_POINTS_PER_TILE);
        shared_view2d_double tile_val_j(team_member.team_scratch(0),
                                        MAX_NEIGHBORS_TILE,
                                        MAX_POINTS_PER_TILE);

        shared_view2d_double tile_gx_i(team_member.team_scratch(0),
                                       MAX_NEIGHBORS_TILE, MAX_POINTS_PER_TILE);

        shared_view2d_double tile_gy_i(team_member.team_scratch(0),
                                       MAX_NEIGHBORS_TILE, MAX_POINTS_PER_TILE);

        shared_view2d_double tile_gz_i(team_member.team_scratch(0),
                                       MAX_NEIGHBORS_TILE, MAX_POINTS_PER_TILE);

        shared_view2d_double tile_gx_j(team_member.team_scratch(0),
                                       MAX_NEIGHBORS_TILE, MAX_POINTS_PER_TILE);

        shared_view2d_double tile_gy_j(team_member.team_scratch(0),
                                       MAX_NEIGHBORS_TILE, MAX_POINTS_PER_TILE);

        shared_view2d_double tile_gz_j(team_member.team_scratch(0),
                                       MAX_NEIGHBORS_TILE, MAX_POINTS_PER_TILE);

        shared_view2d_double tile_overlap(team_member.team_scratch(0),
                                          MAX_NEIGHBORS_TILE,
                                          MAX_NEIGHBORS_TILE);
        shared_view2d_double tile_kinetic(team_member.team_scratch(0),
                                          MAX_NEIGHBORS_TILE,
                                          MAX_NEIGHBORS_TILE);
        shared_view2d_double tile_nuclear(team_member.team_scratch(0),
                                          MAX_NEIGHBORS_TILE,
                                          MAX_NEIGHBORS_TILE);

        for (int tile_i = 0; tile_i < num_tiles; ++tile_i) {
          int num_neighbors_tile_i = Kokkos::min(
              MAX_NEIGHBORS_TILE, num_neighbors - tile_i * MAX_NEIGHBORS_TILE);

          for (int tile_j = 0; tile_j <= tile_i; ++tile_j) {
            int num_neighbors_tile_j =
                Kokkos::min(MAX_NEIGHBORS_TILE,
                            num_neighbors - tile_j * MAX_NEIGHBORS_TILE);

            // Zero output tiles once before point tiling
            Kokkos::parallel_for(Kokkos::TeamThreadMDRange(team_member,
                                                           MAX_NEIGHBORS_TILE,
                                                           MAX_NEIGHBORS_TILE),
                                 [=](int i, int j) {
                                   tile_overlap(i, j) = 0.0;
                                   tile_kinetic(i, j) = 0.0;
                                   tile_nuclear(i, j) = 0.0;
                                 });
            team_member.team_barrier();

            const int num_pt_tiles =
                (num_points + MAX_POINTS_PER_TILE - 1) / MAX_POINTS_PER_TILE;

            for (int pt_tile = 0; pt_tile < num_pt_tiles; ++pt_tile) {
              const int pt_start = pt_tile * MAX_POINTS_PER_TILE;
              const int pt_end =
                  Kokkos::min(pt_start + MAX_POINTS_PER_TILE, num_points);
              const int num_pts = pt_end - pt_start;

              // Fill weights/points/v for this point tile
              Kokkos::parallel_for(
                  Kokkos::TeamVectorRange(team_member, num_pts),
                  [=](const int local_g) {
                    const int global_g = start_points + pt_start + local_g;
                    weights_scratch(local_g) = grid.weights(global_g);
                    points_scratch(local_g) = grid.quad_points(global_g);
                    v_scratch(local_g) = 0.0;
                    for (unsigned k = 0; k < atom_centers.extent(0); ++k) {
                      double r =
                          dist(points_scratch(local_g), atom_centers(k)) +
                          epsilon_shift;
                      v_scratch(local_g) -= double(Z(k)) / r;
                    }
                  });
              team_member.team_barrier();

              // Fill tile_i for this point tile
              Kokkos::parallel_for(
                  Kokkos::TeamThreadRange(team_member, num_neighbors_tile_i),
                  [=](const int local_i) {
                    const int global_i =
                        nl.neighbors(start_neighbors +
                                     tile_i * MAX_NEIGHBORS_TILE + local_i);

                    ScratchBasisParams p{
                        basis.zeta(global_i), basis.norm(global_i),
                        basis.O(global_i),    basis.n(global_i),
                        basis.l(global_i),    basis.m(global_i)};
                    Kokkos::parallel_for(
                        Kokkos::ThreadVectorRange(team_member, num_pts),
                        [=](const int local_g) {
                          basis_eval_with_grad(p, points_scratch(local_g),
                                               tile_val_i(local_i, local_g),
                                               tile_gx_i(local_i, local_g),
                                               tile_gy_i(local_i, local_g),
                                               tile_gz_i(local_i, local_g));
                          tile_val_i(local_i, local_g) *=
                              weights_scratch(local_g);
                          tile_nuc_i(local_i, local_g) =
                              tile_val_i(local_i, local_g) * v_scratch(local_g);
                          tile_gx_i(local_i, local_g) *=
                              weights_scratch(local_g);
                          tile_gy_i(local_i, local_g) *=
                              weights_scratch(local_g);
                          tile_gz_i(local_i, local_g) *=
                              weights_scratch(local_g);
                        });
                  });

              // Fill tile_j for this point tile
              Kokkos::parallel_for(
                  Kokkos::TeamThreadRange(team_member, num_neighbors_tile_j),
                  [=](const int local_j) {
                    const int global_j =
                        nl.neighbors(start_neighbors +
                                     tile_j * MAX_NEIGHBORS_TILE + local_j);
                    ScratchBasisParams p{
                        basis.zeta(global_j), basis.norm(global_j),
                        basis.O(global_j),    basis.n(global_j),
                        basis.l(global_j),    basis.m(global_j)};
                    Kokkos::parallel_for(
                        Kokkos::ThreadVectorRange(team_member, num_pts),
                        [=](const int local_g) {
                          basis_eval_with_grad(p, points_scratch(local_g),
                                               tile_val_j(local_j, local_g),
                                               tile_gx_j(local_j, local_g),
                                               tile_gy_j(local_j, local_g),
                                               tile_gz_j(local_j, local_g));
                        });
                  });

              team_member.team_barrier();

              auto val_i = Kokkos::subview(tile_val_i, Kokkos::ALL,
                                           Kokkos::make_pair(0, num_pts));
              auto nuc_i = Kokkos::subview(tile_nuc_i, Kokkos::ALL,
                                           Kokkos::make_pair(0, num_pts));
              auto val_j = Kokkos::subview(tile_val_j, Kokkos::ALL,
                                           Kokkos::make_pair(0, num_pts));
              auto gx_i = Kokkos::subview(tile_gx_i, Kokkos::ALL,
                                          Kokkos::make_pair(0, num_pts));
              auto gy_i = Kokkos::subview(tile_gy_i, Kokkos::ALL,
                                          Kokkos::make_pair(0, num_pts));
              auto gz_i = Kokkos::subview(tile_gz_i, Kokkos::ALL,
                                          Kokkos::make_pair(0, num_pts));
              auto gx_j = Kokkos::subview(tile_gx_j, Kokkos::ALL,
                                          Kokkos::make_pair(0, num_pts));
              auto gy_j = Kokkos::subview(tile_gy_j, Kokkos::ALL,
                                          Kokkos::make_pair(0, num_pts));
              auto gz_j = Kokkos::subview(tile_gz_j, Kokkos::ALL,
                                          Kokkos::make_pair(0, num_pts));
              // Accumulate into output tiles across pt_tiles — beta=1.0 always
              // since we zeroed output tiles before the pt_tile loop
              KokkosBatched::TeamGemm<
                  member_type, KokkosBatched::Trans::NoTranspose,
                  KokkosBatched::Trans::Transpose,
                  KokkosBatched::Algo::Gemm::Unblocked>::invoke(team_member,
                                                                1.0, val_i,
                                                                val_j, 1.0,
                                                                tile_overlap);

              KokkosBatched::TeamGemm<
                  member_type, KokkosBatched::Trans::NoTranspose,
                  KokkosBatched::Trans::Transpose,
                  KokkosBatched::Algo::Gemm::Unblocked>::invoke(team_member,
                                                                1.0, nuc_i,
                                                                val_j, 1.0,
                                                                tile_nuclear);

              KokkosBatched::TeamGemm<
                  member_type, KokkosBatched::Trans::NoTranspose,
                  KokkosBatched::Trans::Transpose,
                  KokkosBatched::Algo::Gemm::Unblocked>::invoke(team_member,
                                                                0.5, gx_i, gx_j,
                                                                1.0,
                                                                tile_kinetic);
              KokkosBatched::TeamGemm<
                  member_type, KokkosBatched::Trans::NoTranspose,
                  KokkosBatched::Trans::Transpose,
                  KokkosBatched::Algo::Gemm::Unblocked>::invoke(team_member,
                                                                0.5, gy_i, gy_j,
                                                                1.0,
                                                                tile_kinetic);
              KokkosBatched::TeamGemm<
                  member_type, KokkosBatched::Trans::NoTranspose,
                  KokkosBatched::Trans::Transpose,
                  KokkosBatched::Algo::Gemm::Unblocked>::invoke(team_member,
                                                                0.5, gz_i, gz_j,
                                                                1.0,
                                                                tile_kinetic);

              team_member.team_barrier();
            } // pt_tile loop

            // Single scatter after all point tiles
            Kokkos::parallel_for(
                Kokkos::TeamThreadMDRange(team_member, num_neighbors_tile_i,
                                          num_neighbors_tile_j),
                [=](const int local_i, const int local_j) {
                  const int global_i = nl.neighbors(
                      start_neighbors + tile_i * MAX_NEIGHBORS_TILE + local_i);
                  const int global_j = nl.neighbors(
                      start_neighbors + tile_j * MAX_NEIGHBORS_TILE + local_j);
                  Kokkos::atomic_add(&result.overlap(global_i, global_j),
                                     tile_overlap(local_i, local_j));
                  Kokkos::atomic_add(&result.kinetic(global_i, global_j),
                                     tile_kinetic(local_i, local_j));
                  Kokkos::atomic_add(&result.nuclear(global_i, global_j),
                                     tile_nuclear(local_i, local_j));
                  if (tile_i != tile_j) {
                    Kokkos::atomic_add(&result.overlap(global_j, global_i),
                                       tile_overlap(local_i, local_j));
                    Kokkos::atomic_add(&result.kinetic(global_j, global_i),
                                       tile_kinetic(local_i, local_j));
                    Kokkos::atomic_add(&result.nuclear(global_j, global_i),
                                       tile_nuclear(local_i, local_j));
                  }
                });
          } // tile_j
        } // tile_i
      });

  ExecSpace().fence();
  Kokkos::parallel_for(
      "Compute Core Hamiltonian "
      "Matrix",
      Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>({0, 0}, {N, N}),
      KOKKOS_LAMBDA(const int i, const int j) {
        result.hamiltonian(i, j) = result.kinetic(i, j) + result.nuclear(i, j);
      });

  Kokkos::fence();
  return result;
}

CoreHamiltonianResult compute_core_hamiltonian_screened_sparse(
    const STOBasisSet &basis, const FlatGrid &grid, const NeighborList &nl) {
  int N = basis.nbf();
  auto Z = grid.Z;
  auto atom_centers = grid.atom_centers;

  const int max_points_per_box = nl.max_points_per_box;
  const int total_points = nl.total_points;
  const int num_boxes = nl.offsets.extent(0) - 1;

  CoreHamiltonianResult result;
  result.overlap = DeviceView2DLeft("Overlap matrix", N, N);
  result.kinetic = DeviceView2DLeft("Kinetic matrix", N, N);
  result.nuclear = DeviceView2DLeft("Nuclear potential matrix", N, N);
  result.hamiltonian = DeviceView2DLeft("Core Hamiltonian", N, N);

  const int num_neighbors = nl.neighbors.extent(0);

  // We want Right layout on CPU and Left Layout on GPU, Kokkos should do this
  // natively
  Kokkos::View<double **, ExecSpace> sparse_basis_val(
      "Basis Values", num_neighbors, max_points_per_box);

  Kokkos::View<double **, ExecSpace> sparse_basis_gx(
      "Basis  Grad x", num_neighbors, max_points_per_box);
  Kokkos::View<double **, ExecSpace> sparse_basis_gy(
      "Basis  Grad y", num_neighbors, max_points_per_box);
  Kokkos::View<double **, ExecSpace> sparse_basis_gz(
      "Basis  Grad z", num_neighbors, max_points_per_box);

  // Define helpers for scratch space access
  typedef ExecSpace::scratch_memory_space ScratchSpace;

  typedef Kokkos::View<ScratchBasisParams *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_basis;

  typedef Kokkos::View<double *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_double;

  typedef Kokkos::View<Point *, ScratchSpace,
                       Kokkos::MemoryTraits<Kokkos::Unmanaged>>
      shared_view_points;

  Kokkos::TeamPolicy<ExecSpace> policy(num_boxes, Kokkos::AUTO());
  using member_type = Kokkos::TeamPolicy<ExecSpace>::member_type;

  int scratch_size = shared_view_double::shmem_size(max_points_per_box) +
                     shared_view_double::shmem_size(max_points_per_box) +
                     shared_view_points::shmem_size(max_points_per_box);

  policy.set_scratch_size(0, Kokkos::PerTeam(scratch_size));

  Kokkos::parallel_for(
      "Compute Core Hamiltonian Screened Sparse", policy,
      KOKKOS_LAMBDA(const member_type &team_member) {
        const int box_idx = team_member.league_rank();

        // Compute number of points per box
        const int start_points = box_idx * max_points_per_box;
        const int end_points =
            Kokkos::min(start_points + max_points_per_box, total_points);
        const int num_points = end_points - start_points;

        // Compute number of neighbors per box
        const int start_neighbors = nl.offsets(box_idx);
        const int end_neighbors = nl.offsets(box_idx + 1);
        const int num_neighbors = end_neighbors - start_neighbors;

        shared_view_double weights_scratch(team_member.team_scratch(0),
                                           num_points);
        shared_view_double v_scratch(team_member.team_scratch(0), num_points);

        shared_view_points points_scratch(team_member.team_scratch(0),
                                          num_points);

        auto subview_sparse_basis_val = Kokkos::subview(
            sparse_basis_val,
            Kokkos::make_pair(start_neighbors, start_neighbors + num_neighbors),
            Kokkos::ALL());

        auto subview_sparse_basis_gx = Kokkos::subview(
            sparse_basis_gx,
            Kokkos::make_pair(start_neighbors, start_neighbors + num_neighbors),
            Kokkos::ALL());
        auto subview_sparse_basis_gy = Kokkos::subview(
            sparse_basis_gy,
            Kokkos::make_pair(start_neighbors, start_neighbors + num_neighbors),
            Kokkos::ALL());
        auto subview_sparse_basis_gz = Kokkos::subview(
            sparse_basis_gz,
            Kokkos::make_pair(start_neighbors, start_neighbors + num_neighbors),
            Kokkos::ALL());

        Kokkos::parallel_for(
            Kokkos::TeamVectorRange(team_member, num_points),
            [=](const int local_g) {
              const int global_g = start_points + local_g;
              weights_scratch(local_g) = grid.weights(global_g);
              points_scratch(local_g) = grid.quad_points(global_g);
              v_scratch(local_g) = 0.0;
              for (unsigned k = 0; k < atom_centers.extent(0); ++k) {
                double r = dist(points_scratch(local_g), atom_centers(k)) +
                           epsilon_shift;
                v_scratch(local_g) -= double(Z(k)) / r;
              }
              v_scratch(local_g) = v_scratch(local_g);
            });

        team_member.team_barrier();
        // Compute all basis functions
        Kokkos::parallel_for(
            Kokkos::TeamThreadRange(team_member, num_neighbors),
            [=](const int local_i) {
              const int global_i = nl.neighbors(start_neighbors + local_i);
              ScratchBasisParams local_basis_i{
                  basis.zeta(global_i), basis.norm(global_i),
                  basis.O(global_i),    basis.n(global_i),
                  basis.l(global_i),    basis.m(global_i)};

              Kokkos::parallel_for(
                  Kokkos::ThreadVectorRange(team_member, num_points),
                  [=](const int local_g) {
                    basis_eval_with_grad(
                        local_basis_i, points_scratch(local_g),
                        subview_sparse_basis_val(local_i, local_g),
                        subview_sparse_basis_gx(local_i, local_g),
                        subview_sparse_basis_gy(local_i, local_g),
                        subview_sparse_basis_gz(local_i, local_g));
                  });
            });

        team_member.team_barrier();
        Kokkos::parallel_for(
            Kokkos::TeamThreadMDRange(team_member, num_neighbors,
                                      num_neighbors),
            [=](const int local_i, const int local_j) {
              const int global_i = nl.neighbors(start_neighbors + local_i);
              const int global_j = nl.neighbors(start_neighbors + local_j);

              if (global_i < global_j)
                return;

              double total_s = 0.0;
              double total_t = 0.0;
              double total_v = 0.0;

              Kokkos::parallel_reduce(
                  Kokkos::ThreadVectorRange(team_member, num_points),
                  [=](const int local_g, double &update_s, double &update_t,
                      double &update_v) {
                    const double local_s =
                        weights_scratch(local_g) *
                        subview_sparse_basis_val(local_i, local_g) *
                        subview_sparse_basis_val(local_j, local_g);

                    update_s += local_s;
                    update_t += 0.5 * weights_scratch(local_g) *
                                (subview_sparse_basis_gx(local_i, local_g) *
                                     subview_sparse_basis_gx(local_j, local_g) +
                                 subview_sparse_basis_gy(local_i, local_g) *
                                     subview_sparse_basis_gy(local_j, local_g) +
                                 subview_sparse_basis_gz(local_i, local_g) *
                                     subview_sparse_basis_gz(local_j, local_g));
                    update_v += v_scratch(local_g) * local_s;
                  },
                  total_s, total_t, total_v);

              Kokkos::atomic_add(&result.overlap(global_i, global_j), total_s);
              Kokkos::atomic_add(&result.kinetic(global_i, global_j), total_t);
              Kokkos::atomic_add(&result.nuclear(global_i, global_j), total_v);
              if (global_i != global_j) {
                Kokkos::atomic_add(&result.overlap(global_j, global_i),
                                   total_s);
                Kokkos::atomic_add(&result.kinetic(global_j, global_i),
                                   total_t);
                Kokkos::atomic_add(&result.nuclear(global_j, global_i),
                                   total_v);
              }
            });
      });

  ExecSpace().fence();
  Kokkos::parallel_for(
      "Compute Core Hamiltonian Matrix",
      Kokkos::MDRangePolicy<ExecSpace, Kokkos::Rank<2>>({0, 0}, {N, N}),
      KOKKOS_LAMBDA(const int i, const int j) {
        result.hamiltonian(i, j) = result.kinetic(i, j) + result.nuclear(i, j);
      });

  Kokkos::fence();
  return result;
}
} // namespace NuKEXC
  //
  //
