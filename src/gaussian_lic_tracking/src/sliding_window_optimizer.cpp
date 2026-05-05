// SPDX-License-Identifier: GPL-3.0-or-later

#include <gaussian_lic_tracking/sliding_window_optimizer.hpp>

#include <algorithm>
#include <cmath>
#include <stdexcept>

#include <Eigen/Dense>

namespace gaussian_lic_tracking
{
namespace
{
constexpr size_t kStateDof = 15U;

ImuState to_imu_state(const SlidingWindowState & state)
{
  ImuState output;
  output.stamp_ns = state.stamp_ns;
  output.p_w_i = state.p_w_i;
  output.q_w_i = state.q_w_i.normalized();
  output.v_w_i = state.v_w_i;
  output.gyro_bias = state.gyro_bias;
  output.accel_bias = state.accel_bias;
  return output;
}

Eigen::MatrixXd sqrt_information_from_hessian(const Eigen::MatrixXd & hessian)
{
  if (hessian.rows() != hessian.cols() || hessian.rows() == 0 || !hessian.allFinite()) {
    return {};
  }
  const Eigen::MatrixXd symmetric = 0.5 * (hessian + hessian.transpose());
  const Eigen::SelfAdjointEigenSolver<Eigen::MatrixXd> solver(symmetric);
  if (solver.info() != Eigen::Success) {
    return {};
  }
  Eigen::VectorXd sqrt_values(solver.eigenvalues().size());
  for (Eigen::Index i = 0; i < solver.eigenvalues().size(); ++i) {
    sqrt_values[i] = std::sqrt(std::max(0.0, solver.eigenvalues()[i]));
  }
  return sqrt_values.asDiagonal() * solver.eigenvectors().transpose();
}

Eigen::Matrix3d skew_symmetric(const Eigen::Vector3d & value)
{
  Eigen::Matrix3d skew;
  skew << 0.0, -value.z(), value.y(),
    value.z(), 0.0, -value.x(),
    -value.y(), value.x(), 0.0;
  return skew;
}
}  // namespace

SchurComplementResult compute_schur_complement(
  const Eigen::MatrixXd & h_mm,
  const Eigen::MatrixXd & h_mr,
  const Eigen::MatrixXd & h_rr,
  const Eigen::VectorXd & rhs_m,
  const Eigen::VectorXd & rhs_r,
  const double damping)
{
  SchurComplementResult result;
  if (h_mm.rows() != h_mm.cols() || h_rr.rows() != h_rr.cols() ||
    h_mr.rows() != h_mm.rows() || h_mr.cols() != h_rr.rows() ||
    rhs_m.size() != h_mm.rows() || rhs_r.size() != h_rr.rows() ||
    damping < 0.0)
  {
    return result;
  }

  Eigen::MatrixXd regularized_mm = h_mm;
  if (damping > 0.0) {
    regularized_mm += damping * Eigen::MatrixXd::Identity(h_mm.rows(), h_mm.cols());
  }
  const Eigen::LDLT<Eigen::MatrixXd> ldlt(regularized_mm);
  if (ldlt.info() != Eigen::Success) {
    return result;
  }
  const Eigen::MatrixXd solved_mr = ldlt.solve(h_mr);
  const Eigen::VectorXd solved_rhs = ldlt.solve(rhs_m);
  if (!solved_mr.allFinite() || !solved_rhs.allFinite()) {
    return result;
  }

  result.hessian = h_rr - h_mr.transpose() * solved_mr;
  result.rhs = rhs_r - h_mr.transpose() * solved_rhs;
  result.valid = result.hessian.allFinite() && result.rhs.allFinite();
  return result;
}

SlidingWindowOptimizer::SlidingWindowOptimizer(SlidingWindowConfig config)
{
  set_config(config);
}

void SlidingWindowOptimizer::set_config(const SlidingWindowConfig & config)
{
  if (config.max_states < 2U) {
    throw std::runtime_error("sliding window must keep at least two states");
  }
  if (config.max_iterations == 0U) {
    throw std::runtime_error("sliding window optimizer must run at least one iteration");
  }
  if (config.damping <= 0.0 || config.step_tolerance <= 0.0 || config.numeric_epsilon <= 0.0) {
    throw std::runtime_error("sliding window optimizer numeric settings must be positive");
  }
  if (config.marginalization_prior_weight < 0.0) {
    throw std::runtime_error("sliding window marginalization prior weight must be non-negative");
  }
  config_ = config;
}

void SlidingWindowOptimizer::clear()
{
  states_.clear();
  imu_factors_.clear();
  pose_priors_.clear();
  state_priors_.clear();
  dense_priors_.clear();
  point_factors_.clear();
  plane_factors_.clear();
  visual_factors_.clear();
  marginalized_state_count_ = 0U;
}

int SlidingWindowOptimizer::find_state_index(const int64_t stamp_ns) const
{
  const auto it = std::find_if(
    states_.begin(), states_.end(),
    [stamp_ns](const SlidingWindowState & state) {
      return state.stamp_ns == stamp_ns;
    });
  if (it == states_.end()) {
    return -1;
  }
  return static_cast<int>(std::distance(states_.begin(), it));
}

void SlidingWindowOptimizer::add_or_update_state(const SlidingWindowState & state)
{
  SlidingWindowState normalized = state;
  normalized.q_w_i.normalize();
  const int existing = find_state_index(normalized.stamp_ns);
  if (existing >= 0) {
    states_[static_cast<size_t>(existing)] = normalized;
  } else {
    states_.push_back(normalized);
    std::sort(
      states_.begin(), states_.end(),
      [](const SlidingWindowState & lhs, const SlidingWindowState & rhs) {
        return lhs.stamp_ns < rhs.stamp_ns;
      });
  }
  enforce_window_size();
}

bool SlidingWindowOptimizer::get_state(const int64_t stamp_ns, SlidingWindowState & state) const
{
  const int index = find_state_index(stamp_ns);
  if (index < 0) {
    return false;
  }
  state = states_[static_cast<size_t>(index)];
  return true;
}

void SlidingWindowOptimizer::add_imu_factor(const SlidingWindowImuFactor & factor)
{
  if (factor.to_stamp_ns <= factor.from_stamp_ns) {
    throw std::runtime_error("IMU factor timestamps must be strictly increasing");
  }
  if (factor.weight <= 0.0) {
    throw std::runtime_error("IMU factor weight must be positive");
  }
  imu_factors_.push_back(factor);
  enforce_window_size();
}

void SlidingWindowOptimizer::add_pose_prior(const SlidingWindowPosePrior & prior)
{
  if (prior.translation_weight < 0.0 || prior.rotation_weight < 0.0) {
    throw std::runtime_error("pose prior weights must be non-negative");
  }
  SlidingWindowPosePrior normalized = prior;
  normalized.q_w_i.normalize();
  pose_priors_.push_back(normalized);
  enforce_window_size();
}

void SlidingWindowOptimizer::add_state_prior(const SlidingWindowStatePrior & prior)
{
  if (prior.rotation_weight < 0.0 || prior.velocity_weight < 0.0 ||
    prior.position_weight < 0.0 || prior.gyro_bias_weight < 0.0 ||
    prior.accel_bias_weight < 0.0)
  {
    throw std::runtime_error("state prior weights must be non-negative");
  }
  SlidingWindowStatePrior normalized = prior;
  normalized.q_w_i.normalize();
  state_priors_.push_back(normalized);
  enforce_window_size();
}

void SlidingWindowOptimizer::add_dense_prior(const SlidingWindowDensePrior & prior)
{
  const auto expected_cols = static_cast<Eigen::Index>(prior.reference_states.size() * kStateDof);
  if (prior.stamp_ns.size() != prior.reference_states.size() ||
    prior.sqrt_information.cols() != expected_cols ||
    prior.target_delta.size() != expected_cols ||
    prior.sqrt_information.rows() == 0)
  {
    throw std::runtime_error("dense prior dimensions must match referenced states");
  }
  if (!prior.sqrt_information.allFinite() || !prior.target_delta.allFinite()) {
    throw std::runtime_error("dense prior values must be finite");
  }
  SlidingWindowDensePrior normalized = prior;
  for (auto & state : normalized.reference_states) {
    state.q_w_i.normalize();
  }
  dense_priors_.push_back(std::move(normalized));
  enforce_window_size();
}

void SlidingWindowOptimizer::add_point_to_point_factor(const SlidingWindowPointToPointFactor & factor)
{
  if (factor.weight <= 0.0) {
    throw std::runtime_error("point-to-point factor weight must be positive");
  }
  if (factor.frame_points_i.size() != factor.target_points_w.size()) {
    throw std::runtime_error("point-to-point factor source/target sizes must match");
  }
  if (!factor.point_weights.empty() && factor.point_weights.size() != factor.frame_points_i.size()) {
    throw std::runtime_error("point-to-point factor weights must match correspondences");
  }
  if (factor.frame_points_i.empty()) {
    return;
  }
  point_factors_.push_back(factor);
  enforce_window_size();
}

void SlidingWindowOptimizer::add_point_to_plane_factor(const SlidingWindowPointToPlaneFactor & factor)
{
  if (factor.weight <= 0.0) {
    throw std::runtime_error("point-to-plane factor weight must be positive");
  }
  if (factor.frame_points_i.size() != factor.target_points_w.size() ||
    factor.frame_points_i.size() != factor.target_normals_w.size())
  {
    throw std::runtime_error("point-to-plane factor source/target/normal sizes must match");
  }
  if (!factor.point_weights.empty() && factor.point_weights.size() != factor.frame_points_i.size()) {
    throw std::runtime_error("point-to-plane factor weights must match correspondences");
  }
  if (factor.frame_points_i.empty()) {
    return;
  }
  plane_factors_.push_back(factor);
  enforce_window_size();
}

void SlidingWindowOptimizer::add_visual_alignment_factor(const SlidingWindowVisualAlignmentFactor & factor)
{
  if (factor.weight <= 0.0 || factor.meters_per_pixel <= 0.0) {
    throw std::runtime_error("visual alignment factor weight and meters_per_pixel must be positive");
  }
  if (!factor.measured_shift_px.allFinite() || !factor.reference_p_w_i.allFinite()) {
    throw std::runtime_error("visual alignment factor values must be finite");
  }
  visual_factors_.push_back(factor);
  enforce_window_size();
}

SlidingWindowStatePrior SlidingWindowOptimizer::make_state_prior(const SlidingWindowState & state) const
{
  SlidingWindowStatePrior prior;
  prior.stamp_ns = state.stamp_ns;
  prior.p_w_i = state.p_w_i;
  prior.q_w_i = state.q_w_i.normalized();
  prior.v_w_i = state.v_w_i;
  prior.gyro_bias = state.gyro_bias;
  prior.accel_bias = state.accel_bias;
  prior.sqrt_information.setZero();
  prior.sqrt_information.template block<3, 3>(0, 0) =
    std::sqrt(config_.marginalization_prior_weight) * Eigen::Matrix3d::Identity();
  prior.sqrt_information.template block<3, 3>(3, 3) =
    std::sqrt(config_.marginalization_prior_weight) * Eigen::Matrix3d::Identity();
  prior.sqrt_information.template block<3, 3>(6, 6) =
    std::sqrt(config_.marginalization_prior_weight) * Eigen::Matrix3d::Identity();
  prior.sqrt_information.template block<3, 3>(9, 9) =
    std::sqrt(config_.marginalization_prior_weight) * Eigen::Matrix3d::Identity();
  prior.sqrt_information.template block<3, 3>(12, 12) =
    std::sqrt(config_.marginalization_prior_weight) * Eigen::Matrix3d::Identity();
  prior.rotation_weight = config_.marginalization_prior_weight;
  prior.velocity_weight = config_.marginalization_prior_weight;
  prior.position_weight = config_.marginalization_prior_weight;
  prior.gyro_bias_weight = config_.marginalization_prior_weight;
  prior.accel_bias_weight = config_.marginalization_prior_weight;
  return prior;
}

size_t SlidingWindowOptimizer::enforce_window_size()
{
  size_t marginalized = 0U;
  while (states_.size() > config_.max_states) {
    const bool added_schur_prior = add_schur_marginalization_prior_for_front();
    const int64_t stamp_ns = states_.front().stamp_ns;
    states_.erase(states_.begin());
    ++marginalized;
    ++marginalized_state_count_;
    imu_factors_.erase(
      std::remove_if(
        imu_factors_.begin(), imu_factors_.end(),
        [stamp_ns](const SlidingWindowImuFactor & factor) {
          return factor.from_stamp_ns == stamp_ns || factor.to_stamp_ns == stamp_ns;
        }),
      imu_factors_.end());
    pose_priors_.erase(
      std::remove_if(
        pose_priors_.begin(), pose_priors_.end(),
        [stamp_ns](const SlidingWindowPosePrior & prior) {
          return prior.stamp_ns == stamp_ns;
        }),
      pose_priors_.end());
    state_priors_.erase(
      std::remove_if(
        state_priors_.begin(), state_priors_.end(),
        [stamp_ns](const SlidingWindowStatePrior & prior) {
          return prior.stamp_ns == stamp_ns;
        }),
      state_priors_.end());
    dense_priors_.erase(
      std::remove_if(
        dense_priors_.begin(), dense_priors_.end(),
        [stamp_ns](const SlidingWindowDensePrior & prior) {
          return std::find(prior.stamp_ns.begin(), prior.stamp_ns.end(), stamp_ns) !=
                 prior.stamp_ns.end();
        }),
      dense_priors_.end());
    point_factors_.erase(
      std::remove_if(
        point_factors_.begin(), point_factors_.end(),
        [stamp_ns](const SlidingWindowPointToPointFactor & factor) {
          return factor.stamp_ns == stamp_ns;
        }),
      point_factors_.end());
    plane_factors_.erase(
      std::remove_if(
        plane_factors_.begin(), plane_factors_.end(),
        [stamp_ns](const SlidingWindowPointToPlaneFactor & factor) {
          return factor.stamp_ns == stamp_ns;
        }),
      plane_factors_.end());
    visual_factors_.erase(
      std::remove_if(
        visual_factors_.begin(), visual_factors_.end(),
        [stamp_ns](const SlidingWindowVisualAlignmentFactor & factor) {
          return factor.stamp_ns == stamp_ns;
        }),
      visual_factors_.end());
    if (!added_schur_prior && !states_.empty() && config_.marginalization_prior_weight > 0.0) {
      const int64_t anchor_stamp_ns = states_.front().stamp_ns;
      state_priors_.erase(
        std::remove_if(
          state_priors_.begin(), state_priors_.end(),
          [anchor_stamp_ns](const SlidingWindowStatePrior & prior) {
            return prior.stamp_ns == anchor_stamp_ns;
          }),
        state_priors_.end());
      state_priors_.push_back(make_state_prior(states_.front()));
    }
  }
  return marginalized;
}

std::vector<SlidingWindowOptimizer::VariableBlock> SlidingWindowOptimizer::variable_layout() const
{
  std::vector<VariableBlock> variables;
  variables.reserve(states_.size());
  size_t offset = 0U;
  for (size_t index = 0; index < states_.size(); ++index) {
    if (states_[index].fixed) {
      continue;
    }
    variables.push_back(VariableBlock{index, offset});
    offset += kStateDof;
  }
  return variables;
}

Eigen::Vector3d SlidingWindowOptimizer::rotation_residual(
  const Eigen::Quaterniond & measured_q,
  const Eigen::Quaterniond & predicted_q)
{
  Eigen::Quaterniond error = (measured_q.normalized().inverse() * predicted_q.normalized()).normalized();
  if (error.w() < 0.0) {
    error.coeffs() *= -1.0;
  }
  return 2.0 * error.vec();
}

Eigen::Matrix<double, 15, 1> SlidingWindowOptimizer::state_delta(
  const SlidingWindowState & reference,
  const SlidingWindowState & state)
{
  Eigen::Matrix<double, 15, 1> delta;
  delta.template segment<3>(0) = rotation_residual(reference.q_w_i, state.q_w_i);
  delta.template segment<3>(3) = state.v_w_i - reference.v_w_i;
  delta.template segment<3>(6) = state.p_w_i - reference.p_w_i;
  delta.template segment<3>(9) = state.gyro_bias - reference.gyro_bias;
  delta.template segment<3>(12) = state.accel_bias - reference.accel_bias;
  return delta;
}

Eigen::VectorXd SlidingWindowOptimizer::build_residual(
  const std::vector<SlidingWindowState> & states) const
{
  std::vector<double> values;
  values.reserve(
    imu_factors_.size() * 15U + pose_priors_.size() * 6U + state_priors_.size() * 15U +
    dense_priors_.size() * 30U + point_factors_.size() * 300U + plane_factors_.size() * 100U +
    visual_factors_.size() * 2U);

  auto append = [&values](const Eigen::VectorXd & residual) {
      for (Eigen::Index i = 0; i < residual.size(); ++i) {
        values.push_back(residual[i]);
      }
    };

  auto find_local = [&states](const int64_t stamp_ns) -> int {
      const auto it = std::find_if(
        states.begin(), states.end(),
        [stamp_ns](const SlidingWindowState & state) {
          return state.stamp_ns == stamp_ns;
        });
      if (it == states.end()) {
        return -1;
      }
      return static_cast<int>(std::distance(states.begin(), it));
    };

  for (const auto & factor : imu_factors_) {
    const int from = find_local(factor.from_stamp_ns);
    const int to = find_local(factor.to_stamp_ns);
    if (from < 0 || to < 0) {
      continue;
    }
    const ImuBias start_bias{
      states[static_cast<size_t>(from)].gyro_bias,
      states[static_cast<size_t>(from)].accel_bias};
    const auto corrected_preintegration = factor.preintegration.reintegrated(start_bias);
    const auto residual = corrected_preintegration.residual(
      to_imu_state(states[static_cast<size_t>(from)]),
      to_imu_state(states[static_cast<size_t>(to)]),
      factor.gravity_w);
    append(std::sqrt(factor.weight) * residual.residual);
    Eigen::Matrix<double, 6, 1> bias_residual;
    bias_residual.template segment<3>(0) =
      states[static_cast<size_t>(to)].gyro_bias - states[static_cast<size_t>(from)].gyro_bias;
    bias_residual.template segment<3>(3) =
      states[static_cast<size_t>(to)].accel_bias - states[static_cast<size_t>(from)].accel_bias;
    append(std::sqrt(factor.bias_weight) * bias_residual);
  }

  for (const auto & prior : pose_priors_) {
    const int index = find_local(prior.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    Eigen::Matrix<double, 6, 1> residual;
    residual.template segment<3>(0) =
      std::sqrt(prior.rotation_weight) * rotation_residual(prior.q_w_i, state.q_w_i);
    residual.template segment<3>(3) =
      std::sqrt(prior.translation_weight) * (state.p_w_i - prior.p_w_i);
    append(residual);
  }

  for (const auto & prior : state_priors_) {
    const int index = find_local(prior.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    Eigen::Matrix<double, 15, 1> residual;
    residual.template segment<3>(0) =
      rotation_residual(prior.q_w_i, state.q_w_i);
    residual.template segment<3>(3) =
      state.v_w_i - prior.v_w_i;
    residual.template segment<3>(6) =
      state.p_w_i - prior.p_w_i;
    residual.template segment<3>(9) =
      state.gyro_bias - prior.gyro_bias;
    residual.template segment<3>(12) =
      state.accel_bias - prior.accel_bias;
    Eigen::Matrix<double, 15, 15> sqrt_information = prior.sqrt_information;
    if (sqrt_information.isApprox(Eigen::Matrix<double, 15, 15>::Identity())) {
      sqrt_information.setZero();
      sqrt_information.template block<3, 3>(0, 0) =
        std::sqrt(prior.rotation_weight) * Eigen::Matrix3d::Identity();
      sqrt_information.template block<3, 3>(3, 3) =
        std::sqrt(prior.velocity_weight) * Eigen::Matrix3d::Identity();
      sqrt_information.template block<3, 3>(6, 6) =
        std::sqrt(prior.position_weight) * Eigen::Matrix3d::Identity();
      sqrt_information.template block<3, 3>(9, 9) =
        std::sqrt(prior.gyro_bias_weight) * Eigen::Matrix3d::Identity();
      sqrt_information.template block<3, 3>(12, 12) =
        std::sqrt(prior.accel_bias_weight) * Eigen::Matrix3d::Identity();
    }
    append(sqrt_information * residual);
  }

  for (const auto & prior : dense_priors_) {
    const auto prior_cols = static_cast<Eigen::Index>(prior.reference_states.size() * kStateDof);
    if (prior.sqrt_information.cols() != prior_cols || prior.target_delta.size() != prior_cols) {
      continue;
    }
    Eigen::VectorXd delta(prior_cols);
    bool complete = true;
    for (size_t reference_index = 0; reference_index < prior.reference_states.size(); ++reference_index) {
      const int index = find_local(prior.stamp_ns[reference_index]);
      if (index < 0) {
        complete = false;
        break;
      }
      delta.template segment<15>(static_cast<Eigen::Index>(reference_index * kStateDof)) =
        state_delta(prior.reference_states[reference_index], states[static_cast<size_t>(index)]);
    }
    if (complete) {
      append(prior.sqrt_information * (delta - prior.target_delta));
    }
  }

  for (const auto & factor : point_factors_) {
    const int index = find_local(factor.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    for (size_t point_index = 0; point_index < factor.frame_points_i.size(); ++point_index) {
      const double robust_weight = factor.point_weights.empty()
        ? 1.0
        : std::max(0.0, factor.point_weights[point_index]);
      const double scale = std::sqrt(factor.weight * robust_weight);
      Eigen::Vector3d residual =
        state.q_w_i * factor.frame_points_i[point_index] + state.p_w_i -
        factor.target_points_w[point_index];
      append(scale * residual);
    }
  }

  for (const auto & factor : plane_factors_) {
    const int index = find_local(factor.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    Eigen::VectorXd residual(static_cast<Eigen::Index>(factor.frame_points_i.size()));
    for (size_t point_index = 0; point_index < factor.frame_points_i.size(); ++point_index) {
      const double robust_weight = factor.point_weights.empty()
        ? 1.0
        : std::max(0.0, factor.point_weights[point_index]);
      const double scale = std::sqrt(factor.weight * robust_weight);
      const Eigen::Vector3d point_w =
        state.q_w_i * factor.frame_points_i[point_index] + state.p_w_i;
      residual[static_cast<Eigen::Index>(point_index)] =
        scale * factor.target_normals_w[point_index].normalized().dot(
        point_w - factor.target_points_w[point_index]);
    }
    append(residual);
  }

  for (const auto & factor : visual_factors_) {
    const int index = find_local(factor.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    Eigen::Vector2d target_xy;
    target_xy.x() = factor.reference_p_w_i.x() + factor.measured_shift_px.x() * factor.meters_per_pixel;
    target_xy.y() = factor.reference_p_w_i.y() + factor.measured_shift_px.y() * factor.meters_per_pixel;
    Eigen::Vector2d residual;
    residual.x() = state.p_w_i.x() - target_xy.x();
    residual.y() = state.p_w_i.y() - target_xy.y();
    append(std::sqrt(factor.weight) * residual);
  }

  Eigen::VectorXd residual(values.size());
  for (size_t i = 0; i < values.size(); ++i) {
    residual[static_cast<Eigen::Index>(i)] = values[i];
  }
  return residual;
}

double SlidingWindowOptimizer::compute_cost(const Eigen::VectorXd & residual) const
{
  return 0.5 * residual.squaredNorm();
}

std::vector<std::pair<Eigen::Index, Eigen::Index>> SlidingWindowOptimizer::fill_analytic_jacobian(
  const std::vector<SlidingWindowState> & states,
  const std::vector<VariableBlock> & variables,
  Eigen::MatrixXd & jacobian) const
{
  std::vector<std::pair<Eigen::Index, Eigen::Index>> numeric_row_ranges;
  auto mark_numeric = [&numeric_row_ranges](const Eigen::Index start, const Eigen::Index size) {
      if (size > 0) {
        numeric_row_ranges.emplace_back(start, size);
      }
    };
  auto fallback_to_numeric = [&numeric_row_ranges, &mark_numeric, &jacobian]() {
      numeric_row_ranges.clear();
      mark_numeric(0, jacobian.rows());
      return numeric_row_ranges;
    };
  auto rows_available = [&jacobian](const Eigen::Index start, const Eigen::Index size) {
      return start >= 0 && size >= 0 && start + size <= jacobian.rows();
    };
  auto find_local = [&states](const int64_t stamp_ns) -> int {
      const auto it = std::find_if(
        states.begin(), states.end(),
        [stamp_ns](const SlidingWindowState & state) {
          return state.stamp_ns == stamp_ns;
        });
      if (it == states.end()) {
        return -1;
      }
      return static_cast<int>(std::distance(states.begin(), it));
    };

  std::vector<Eigen::Index> variable_offsets(states.size(), -1);
  for (const auto & variable : variables) {
    if (variable.state_index < variable_offsets.size()) {
      variable_offsets[variable.state_index] = static_cast<Eigen::Index>(variable.offset);
    }
  }

  Eigen::Index row = 0;
  for (const auto & factor : imu_factors_) {
    const int from = find_local(factor.from_stamp_ns);
    const int to = find_local(factor.to_stamp_ns);
    if (from < 0 || to < 0) {
      continue;
    }
    mark_numeric(row, 21);
    row += 21;
  }

  for (const auto & prior : pose_priors_) {
    const int index = find_local(prior.stamp_ns);
    if (index < 0) {
      continue;
    }
    mark_numeric(row, 6);
    row += 6;
  }

  for (const auto & prior : state_priors_) {
    const int index = find_local(prior.stamp_ns);
    if (index < 0) {
      continue;
    }
    mark_numeric(row, 15);
    row += 15;
  }

  for (const auto & prior : dense_priors_) {
    const auto prior_cols = static_cast<Eigen::Index>(prior.reference_states.size() * kStateDof);
    if (prior.sqrt_information.cols() != prior_cols || prior.target_delta.size() != prior_cols) {
      continue;
    }
    bool complete = true;
    for (const auto stamp_ns : prior.stamp_ns) {
      if (find_local(stamp_ns) < 0) {
        complete = false;
        break;
      }
    }
    if (complete) {
      mark_numeric(row, prior.sqrt_information.rows());
      row += prior.sqrt_information.rows();
    }
  }

  for (const auto & factor : point_factors_) {
    const int index = find_local(factor.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    const Eigen::Index offset = variable_offsets[static_cast<size_t>(index)];
    for (size_t point_index = 0; point_index < factor.frame_points_i.size(); ++point_index) {
      if (!rows_available(row, 3)) {
        return fallback_to_numeric();
      }
      if (offset >= 0) {
        const double robust_weight = factor.point_weights.empty()
          ? 1.0
          : std::max(0.0, factor.point_weights[point_index]);
        const double scale = std::sqrt(factor.weight * robust_weight);
        const Eigen::Vector3d rotated_point = state.q_w_i * factor.frame_points_i[point_index];
        jacobian.template block<3, 3>(row, offset) =
          scale * -skew_symmetric(rotated_point);
        jacobian.template block<3, 3>(row, offset + 6) =
          scale * Eigen::Matrix3d::Identity();
      }
      row += 3;
    }
  }

  for (const auto & factor : plane_factors_) {
    const int index = find_local(factor.stamp_ns);
    if (index < 0) {
      continue;
    }
    const auto & state = states[static_cast<size_t>(index)];
    const Eigen::Index offset = variable_offsets[static_cast<size_t>(index)];
    for (size_t point_index = 0; point_index < factor.frame_points_i.size(); ++point_index) {
      if (!rows_available(row, 1)) {
        return fallback_to_numeric();
      }
      if (offset >= 0) {
        const double robust_weight = factor.point_weights.empty()
          ? 1.0
          : std::max(0.0, factor.point_weights[point_index]);
        const double scale = std::sqrt(factor.weight * robust_weight);
        const Eigen::Vector3d normal = factor.target_normals_w[point_index].normalized();
        const Eigen::Vector3d rotated_point = state.q_w_i * factor.frame_points_i[point_index];
        jacobian.template block<1, 3>(row, offset) =
          scale * -normal.transpose() * skew_symmetric(rotated_point);
        jacobian.template block<1, 3>(row, offset + 6) =
          scale * normal.transpose();
      }
      ++row;
    }
  }

  for (const auto & factor : visual_factors_) {
    const int index = find_local(factor.stamp_ns);
    if (index < 0) {
      continue;
    }
    const Eigen::Index offset = variable_offsets[static_cast<size_t>(index)];
    if (!rows_available(row, 2)) {
      return fallback_to_numeric();
    }
    if (offset >= 0) {
      const double scale = std::sqrt(factor.weight);
      jacobian(row, offset + 6) = scale;
      jacobian(row + 1, offset + 7) = scale;
    }
    row += 2;
  }

  if (row != jacobian.rows()) {
    numeric_row_ranges.clear();
    mark_numeric(0, jacobian.rows());
  }
  return numeric_row_ranges;
}

bool SlidingWindowOptimizer::add_schur_marginalization_prior_for_front()
{
  if (states_.size() < 2U) {
    return false;
  }
  const auto variables = variable_layout();
  auto marginalized_it = std::find_if(
    variables.begin(), variables.end(),
    [](const VariableBlock & variable) {
      return variable.state_index == 0U;
    });
  if (marginalized_it == variables.end()) {
    return false;
  }

  std::vector<VariableBlock> retained_variables;
  retained_variables.reserve(variables.size() - 1U);
  for (const auto & variable : variables) {
    if (variable.state_index != 0U) {
      retained_variables.push_back(variable);
    }
  }
  if (retained_variables.empty()) {
    return false;
  }

  const auto normal = linearize(states_, variables, 0.0);
  if (!normal.valid || normal.variable_count != variables.size() * kStateDof) {
    return false;
  }
  const auto marginalized_offset = static_cast<Eigen::Index>(marginalized_it->offset);
  constexpr Eigen::Index marginalized_dim = static_cast<Eigen::Index>(kStateDof);
  const auto retained_dim = static_cast<Eigen::Index>(retained_variables.size() * kStateDof);
  Eigen::MatrixXd h_mr(marginalized_dim, retained_dim);
  Eigen::MatrixXd h_rr(retained_dim, retained_dim);
  Eigen::VectorXd rhs_r(retained_dim);

  std::vector<Eigen::Index> retained_columns;
  retained_columns.reserve(static_cast<size_t>(retained_dim));
  for (const auto & variable : retained_variables) {
    for (size_t dim = 0; dim < kStateDof; ++dim) {
      retained_columns.push_back(static_cast<Eigen::Index>(variable.offset + dim));
    }
  }
  for (Eigen::Index row = 0; row < marginalized_dim; ++row) {
    for (Eigen::Index col = 0; col < retained_dim; ++col) {
      h_mr(row, col) = normal.hessian(marginalized_offset + row, retained_columns[static_cast<size_t>(col)]);
    }
  }
  for (Eigen::Index row = 0; row < retained_dim; ++row) {
    rhs_r(row) = normal.rhs(retained_columns[static_cast<size_t>(row)]);
    for (Eigen::Index col = 0; col < retained_dim; ++col) {
      h_rr(row, col) = normal.hessian(
        retained_columns[static_cast<size_t>(row)],
        retained_columns[static_cast<size_t>(col)]);
    }
  }

  const auto schur = compute_schur_complement(
    normal.hessian.block(marginalized_offset, marginalized_offset, marginalized_dim, marginalized_dim),
    h_mr,
    h_rr,
    normal.rhs.segment(marginalized_offset, marginalized_dim),
    rhs_r,
    config_.damping);
  if (!schur.valid || schur.hessian.rows() != retained_dim || schur.rhs.size() != retained_dim) {
    return false;
  }
  if (schur.hessian.norm() <= 1.0e-12) {
    return false;
  }

  const Eigen::MatrixXd regularized =
    schur.hessian + config_.damping * Eigen::MatrixXd::Identity(retained_dim, retained_dim);
  const Eigen::VectorXd target_delta = regularized.ldlt().solve(schur.rhs);
  const Eigen::MatrixXd sqrt_information = sqrt_information_from_hessian(schur.hessian);
  if (!target_delta.allFinite() || sqrt_information.rows() == 0 || !sqrt_information.allFinite()) {
    return false;
  }

  SlidingWindowDensePrior prior;
  prior.sqrt_information = sqrt_information;
  prior.target_delta = target_delta;
  prior.stamp_ns.reserve(retained_variables.size());
  prior.reference_states.reserve(retained_variables.size());
  for (const auto & variable : retained_variables) {
    prior.stamp_ns.push_back(states_[variable.state_index].stamp_ns);
    prior.reference_states.push_back(states_[variable.state_index]);
  }
  dense_priors_.push_back(std::move(prior));
  return true;
}

SlidingWindowNormalEquation SlidingWindowOptimizer::linearize(
  const std::vector<SlidingWindowState> & states,
  const std::vector<VariableBlock> & variables,
  const double damping) const
{
  SlidingWindowNormalEquation output;
  if (damping < 0.0) {
    return output;
  }
  output.residual = build_residual(states);
  output.cost = compute_cost(output.residual);
  output.variable_count = variables.size() * kStateDof;
  const auto variable_count = static_cast<Eigen::Index>(output.variable_count);
  output.jacobian = Eigen::MatrixXd::Zero(output.residual.size(), variable_count);
  output.hessian = Eigen::MatrixXd::Zero(variable_count, variable_count);
  output.rhs = Eigen::VectorXd::Zero(variable_count);
  if (output.variable_count == 0U) {
    output.valid = output.residual.allFinite();
    return output;
  }

  const auto numeric_row_ranges = fill_analytic_jacobian(states, variables, output.jacobian);
  for (size_t column = 0; column < output.variable_count && !numeric_row_ranges.empty(); ++column) {
    Eigen::VectorXd delta = Eigen::VectorXd::Zero(variable_count);
    delta[static_cast<Eigen::Index>(column)] = config_.numeric_epsilon;
    auto plus_states = states;
    auto minus_states = states;
    apply_delta(plus_states, variables, delta, 1.0);
    apply_delta(minus_states, variables, delta, -1.0);
    const Eigen::VectorXd numeric_column =
      (build_residual(plus_states) - build_residual(minus_states)) /
      (2.0 * config_.numeric_epsilon);
    for (const auto & range : numeric_row_ranges) {
      output.jacobian.block(range.first, static_cast<Eigen::Index>(column), range.second, 1) =
        numeric_column.segment(range.first, range.second);
    }
  }

  output.hessian = output.jacobian.transpose() * output.jacobian;
  if (damping > 0.0) {
    output.hessian += damping * Eigen::MatrixXd::Identity(variable_count, variable_count);
  }
  output.rhs = -output.jacobian.transpose() * output.residual;
  output.valid = output.residual.allFinite() && output.jacobian.allFinite() &&
    output.hessian.allFinite() && output.rhs.allFinite();
  return output;
}

SlidingWindowNormalEquation SlidingWindowOptimizer::build_normal_equation(
  const double damping) const
{
  return linearize(states_, variable_layout(), damping);
}

void SlidingWindowOptimizer::apply_delta(
  std::vector<SlidingWindowState> & states,
  const std::vector<VariableBlock> & variables,
  const Eigen::VectorXd & delta,
  const double scale)
{
  for (const auto & variable : variables) {
    auto & state = states[variable.state_index];
    const auto offset = static_cast<Eigen::Index>(variable.offset);
    const Eigen::Vector3d dtheta = scale * delta.template segment<3>(offset);
    const Eigen::Vector3d dv = scale * delta.template segment<3>(offset + 3);
    const Eigen::Vector3d dp = scale * delta.template segment<3>(offset + 6);
    const Eigen::Vector3d dgyro_bias = scale * delta.template segment<3>(offset + 9);
    const Eigen::Vector3d daccel_bias = scale * delta.template segment<3>(offset + 12);
    const double angle = dtheta.norm();
    if (angle > 1.0e-12) {
      state.q_w_i = (Eigen::Quaterniond(Eigen::AngleAxisd(angle, dtheta / angle)) * state.q_w_i).normalized();
    }
    state.v_w_i += dv;
    state.p_w_i += dp;
    state.gyro_bias += dgyro_bias;
    state.accel_bias += daccel_bias;
  }
}

SlidingWindowSummary SlidingWindowOptimizer::optimize()
{
  SlidingWindowSummary summary;
  enforce_window_size();
  summary.marginalized_state_count = marginalized_state_count_;
  summary.state_count = states_.size();
  summary.imu_factor_count = imu_factors_.size();
  summary.pose_prior_count = pose_priors_.size();
  summary.state_prior_count = state_priors_.size();
  summary.dense_prior_count = dense_priors_.size();
  summary.point_factor_count = point_factors_.size();
  summary.plane_factor_count = plane_factors_.size();
  summary.visual_factor_count = visual_factors_.size();
  Eigen::VectorXd residual = build_residual(states_);
  summary.initial_cost = compute_cost(residual);
  summary.final_cost = summary.initial_cost;

  const auto variables = variable_layout();
  const size_t variable_count = variables.size() * kStateDof;
  if (residual.size() == 0 || variable_count == 0U) {
    summary.converged = true;
    return summary;
  }

  double damping = config_.damping;
  for (size_t iteration = 0; iteration < config_.max_iterations; ++iteration) {
    const auto normal_equation = linearize(states_, variables, damping);
    if (!normal_equation.valid) {
      break;
    }
    const double current_cost = normal_equation.cost;
    const Eigen::VectorXd step = normal_equation.hessian.ldlt().solve(normal_equation.rhs);
    if (!step.allFinite()) {
      break;
    }

    auto candidate_states = states_;
    apply_delta(candidate_states, variables, step, 1.0);
    const double candidate_cost = compute_cost(build_residual(candidate_states));
    if (candidate_cost <= current_cost) {
      states_ = std::move(candidate_states);
      summary.iterations = iteration + 1U;
      summary.final_cost = candidate_cost;
      damping = std::max(damping * 0.1, config_.damping);
      if (step.norm() < config_.step_tolerance) {
        summary.converged = true;
        break;
      }
    } else {
      damping *= 10.0;
      summary.final_cost = current_cost;
    }
  }
  if (summary.iterations == config_.max_iterations || summary.final_cost < summary.initial_cost) {
    summary.converged = summary.final_cost <= summary.initial_cost;
  }
  return summary;
}

}  // namespace gaussian_lic_tracking
