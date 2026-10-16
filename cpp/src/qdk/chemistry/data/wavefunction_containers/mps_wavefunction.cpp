// Copyright (c) Microsoft Corporation. All rights reserved.
// Licensed under the MIT License. See LICENSE.txt in the project root for
// license information.

#include <algorithm>
#include <array>
#include <complex>
#include <cstdint>
#include <limits>
#include <numeric>
#include <qdk/chemistry/data/configuration_set.hpp>
#include <qdk/chemistry/data/symmetry/spin_channel_indices.hpp>
#include <qdk/chemistry/data/wavefunction_containers/mps_wavefunction.hpp>
#include <stdexcept>
#include <type_traits>
#include <unordered_map>
#include <utility>
#include <variant>

#include "../json_serialization.hpp"

namespace qdk::chemistry::data {
namespace {

constexpr auto index_limit =
    static_cast<std::size_t>(std::numeric_limits<Eigen::Index>::max());
constexpr std::array<const char*, 3> order_keys{
    "left_sector_order", "physical_sector_order", "right_sector_order"};

template <typename Extents>
std::size_t total_extent(const Extents& extents) {
  std::size_t total = 0;
  for (const auto& [label, extent] : extents) {
    if (extent == 0 || extent > index_limit - total) {
      throw std::invalid_argument(
          "MPS sector extents must be positive and fit Eigen::Index.");
    }
    total += extent;
  }
  return total;
}

template <typename Extents>
std::unordered_map<SymmetryLabel, std::size_t> sector_offsets(
    const Extents& extents, const std::vector<SymmetryLabel>& order) {
  if (order.size() != extents.size()) {
    throw std::invalid_argument(
        "MPS sector order must contain every sector exactly once.");
  }
  std::unordered_map<SymmetryLabel, std::size_t> offsets;
  std::size_t offset = 0;
  for (const auto& label : order) {
    const auto extent = extents.find(label);
    if (extent == extents.end() || !offsets.emplace(label, offset).second) {
      throw std::invalid_argument(
          "MPS sector order contains a missing or duplicate sector.");
    }
    offset += extent->second;
  }
  return offsets;
}

std::vector<Configuration> default_physical_basis(std::size_t dimension) {
  std::vector<Configuration> basis;
  if (dimension == 2) {
    for (const auto* state : {"0", "1"}) {
      basis.push_back(Configuration::from_bitstring(state));
    }
  } else if (dimension == 4) {
    for (const auto* state : {"0", "u", "d", "2"}) {
      basis.push_back(Configuration::from_spin_half_string(state));
    }
  } else {
    throw std::invalid_argument(
        "MPS sites outside dimension two or four require a physical basis.");
  }
  return basis;
}

Eigen::VectorXd natural_occupations(const ContainerTypes::MatrixVariant& rdm) {
  return std::visit(
      [](const auto& matrix) -> Eigen::VectorXd {
        if (!matrix.isApprox(matrix.adjoint())) {
          throw std::runtime_error(
              "Natural occupations require a Hermitian 1-RDM.");
        }
        using Matrix = std::decay_t<decltype(matrix)>;
        Eigen::SelfAdjointEigenSolver<Matrix> solver(matrix,
                                                     Eigen::EigenvaluesOnly);
        if (solver.info() != Eigen::Success) {
          throw std::runtime_error("Failed to diagonalize MPS 1-RDM.");
        }
        return solver.eigenvalues().reverse().eval();
      },
      rdm);
}

std::shared_ptr<const SymmetryBlockedTensorVariant<2>> normalize_one_rdm(
    const std::optional<SymmetryBlockedTensorVariant<2>>& blocked,
    const std::optional<ContainerTypes::MatrixVariant>& aa,
    const std::optional<ContainerTypes::MatrixVariant>& bb) {
  if (blocked && (aa || bb)) {
    throw std::invalid_argument(
        "MPS raw and blocked RDM inputs for the same rank are mutually "
        "exclusive.");
  }
  if (aa.has_value() != bb.has_value()) {
    throw std::invalid_argument(
        "MPS requires both spin blocks of a supplied 1-RDM.");
  }
  if (blocked) {
    return std::make_shared<const SymmetryBlockedTensorVariant<2>>(*blocked);
  }
  // Pass restricted=false so equal raw blocks stay independent copies.
  return aa ? make_spin_diagonal_rank2_sbt_variant(*aa, *bb, false) : nullptr;
}

std::shared_ptr<const SymmetryBlockedTensorVariant<4>> normalize_two_rdm(
    const std::optional<SymmetryBlockedTensorVariant<4>>& blocked,
    const std::optional<ContainerTypes::VectorVariant>& aaaa,
    const std::optional<ContainerTypes::VectorVariant>& aabb,
    const std::optional<ContainerTypes::VectorVariant>& bbbb) {
  if (blocked && (aaaa || aabb || bbbb)) {
    throw std::invalid_argument(
        "MPS raw and blocked RDM inputs for the same rank are mutually "
        "exclusive.");
  }
  if (aaaa.has_value() != aabb.has_value() ||
      aaaa.has_value() != bbbb.has_value()) {
    throw std::invalid_argument(
        "MPS requires all three spin blocks of a supplied 2-RDM.");
  }
  if (blocked) {
    return std::make_shared<const SymmetryBlockedTensorVariant<4>>(*blocked);
  }
  return aaaa ? make_spin_diagonal_rank4_sbt_variant(*aaaa, *aabb, *bbbb, false)
              : nullptr;
}

std::size_t read_index(const nlohmann::json& value) {
  if (!value.is_number_integer() ||
      (!value.is_number_unsigned() && value.get<std::int64_t>() < 0) ||
      value.get<std::uint64_t>() > std::numeric_limits<std::size_t>::max()) {
    throw std::invalid_argument("MPS indices must be nonnegative integers.");
  }
  return value.get<std::size_t>();
}

void validate_metadata(const nlohmann::json& json,
                       const std::string& expected_version) {
  validate_serialization_version(expected_version,
                                 json.at("version").get<std::string>());
  if (json.at("container_type") != "mps") {
    throw std::invalid_argument("Unsupported MPS container type.");
  }
  if (json.at("scalar") != "real" && json.at("scalar") != "complex") {
    throw std::invalid_argument("Unsupported MPS scalar type.");
  }
  if (!json.at("sites").is_array() || json.at("sites").empty() ||
      !json.at("site_to_orbital_order").is_array() ||
      json.at("site_to_orbital_order").empty()) {
    throw std::invalid_argument(
        "Serialized MPS requires explicit sites and ordering.");
  }
}

nlohmann::json site_metadata(const MPSSite& site) {
  nlohmann::json json;
  for (std::size_t slot = 0; slot < order_keys.size(); ++slot) {
    auto& order = json[order_keys[slot]];
    order = nlohmann::json::array();
    for (const auto& label : site.sector_orders()[slot]) {
      order.push_back(label.to_json());
    }
  }
  json["physical_basis"] = nlohmann::json::array();
  for (const auto& state : site.physical_basis()) {
    json["physical_basis"].push_back(state.to_json());
  }
  return json;
}

MPSContainer::SitePtr site_from_metadata(const nlohmann::json& json,
                                         MPSSite::TensorPtr tensor) {
  MPSSite::SectorOrders orders;
  for (std::size_t slot = 0; slot < order_keys.size(); ++slot) {
    const auto& order = json.at(order_keys[slot]);
    if (!order.is_array()) {
      throw std::invalid_argument("MPS sector orders must be arrays.");
    }
    for (const auto& label : order) {
      orders[slot].push_back(SymmetryLabel::from_json(label));
    }
  }
  const auto& basis_json = json.at("physical_basis");
  if (!basis_json.is_array() || basis_json.empty()) {
    throw std::invalid_argument(
        "Serialized MPS sites require a physical basis.");
  }
  std::vector<Configuration> basis;
  for (const auto& state : basis_json) {
    const auto bits = read_index(state.at("bits_per_mode"));
    if (bits != 1 && bits != 2) {
      throw std::invalid_argument(
          "MPS physical states require binary or spin-half configurations.");
    }
    basis.push_back(Configuration::from_json(state));
  }
  return std::make_shared<const MPSSite>(std::move(tensor), std::move(orders),
                                         std::move(basis));
}

std::unique_ptr<MPSContainer> mps_from_metadata(
    const nlohmann::json& json, std::shared_ptr<Orbitals> orbitals,
    std::vector<MPSContainer::SitePtr> sites,
    const OrbitalEntropies& entropies) {
  std::optional<std::size_t> center;
  if (!json.at("orthogonality_center").is_null()) {
    center = read_index(json.at("orthogonality_center"));
  }
  std::vector<std::size_t> order;
  for (const auto& index : json.at("site_to_orbital_order")) {
    order.push_back(read_index(index));
  }
  auto read_counts = [](const nlohmann::json& counts)
      -> std::shared_ptr<const MPSContainer::ParticleCount> {
    return counts.is_null() ? nullptr
                            : MPSContainer::ParticleCount::from_json(counts);
  };
  return std::make_unique<MPSContainer>(
      std::move(sites), std::move(orbitals),
      read_counts(json.at("total_num_particles")),
      read_counts(json.at("active_num_particles")), center, std::move(order),
      std::nullopt, std::nullopt, std::nullopt, std::nullopt, std::nullopt,
      std::nullopt, std::nullopt, std::nullopt, std::nullopt, entropies);
}

/**
 * @brief Contract the chain for one physical index per site.
 * @param sites Sites in chain order, all storing @p Scalar.
 * @param physical Flattened physical index selected on each site.
 * @return Product-basis amplitude of the selected local states.
 */
template <typename Scalar>
Scalar contract_amplitude(const std::vector<MPSContainer::SitePtr>& sites,
                          const std::vector<std::size_t>& physical) {
  using Vector = Eigen::Matrix<Scalar, Eigen::Dynamic, 1>;
  Vector left = Vector::Ones(1);
  for (std::size_t s = 0; s < sites.size(); ++s) {
    const auto& site = *sites[s];
    const auto& tensor =
        std::get<SymmetryBlockedTensor<3, Scalar>>(site.tensor());
    // Locate the physical sector and the index within it.
    const SymmetryLabel* sector = nullptr;
    std::size_t local = physical[s];
    for (const auto& label : site.physical_sector_order()) {
      const auto extent = tensor.extents()[1].at(label);
      if (local < extent) {
        sector = &label;
        break;
      }
      local -= extent;
    }
    const auto physical_extent = tensor.extents()[1].at(*sector);
    const auto left_offsets =
        sector_offsets(tensor.extents()[0], site.left_sector_order());
    const auto right_offsets =
        sector_offsets(tensor.extents()[2], site.right_sector_order());
    Vector right =
        Vector::Zero(static_cast<Eigen::Index>(site.right_bond_dimension()));
    for (const auto& [labels, block] : tensor.blocks()) {
      if (!(labels[1] == *sector)) continue;
      const auto left_offset = left_offsets.at(labels[0]);
      const auto right_offset =
          static_cast<Eigen::Index>(right_offsets.at(labels[2]));
      for (std::size_t l = 0; l < tensor.extents()[0].at(labels[0]); ++l) {
        right.segment(right_offset, block->cols()) +=
            left(static_cast<Eigen::Index>(left_offset + l)) *
            block->row(static_cast<Eigen::Index>(l * physical_extent + local))
                .transpose();
      }
    }
    left = std::move(right);
  }
  return left(0);
}

}  // namespace

MPSSite::MPSSite(TensorPtr tensor, SectorOrders sector_orders,
                 std::vector<Configuration> physical_basis)
    : _tensor(std::move(tensor)),
      _sector_orders(std::move(sector_orders)),
      _physical_basis(std::move(physical_basis)) {
  if (!_tensor) {
    throw std::invalid_argument("MPS site requires a tensor.");
  }
  if (_physical_basis.empty()) {
    _physical_basis = default_physical_basis(physical_dimension());
  }
  _validate();
}

void MPSSite::_validate() const {
  std::visit(
      [&](const auto& tensor) {
        for (std::size_t slot = 0; slot < 3; ++slot) {
          if (total_extent(tensor.extents()[slot]) == 0) {
            throw std::invalid_argument("MPS index spaces must be nonempty.");
          }
          for (const auto& axis : tensor.symmetries()[slot]->axes()) {
            if (axis.equivalent()) {
              throw std::invalid_argument(
                  "MPS axes must not enable equivalent-sector aliasing.");
            }
          }
          sector_offsets(tensor.extents()[slot], _sector_orders[slot]);
        }
        for (const auto& [labels, block] : tensor.blocks()) {
          const auto left = tensor.extents()[0].at(labels[0]);
          const auto physical = tensor.extents()[1].at(labels[1]);
          const auto right = tensor.extents()[2].at(labels[2]);
          if (left > index_limit / physical ||
              block->rows() != static_cast<Eigen::Index>(left * physical) ||
              block->cols() != static_cast<Eigen::Index>(right)) {
            throw std::invalid_argument(
                "MPS blocks must be packed as (left * physical, right).");
          }
          if (!block->allFinite()) {
            throw std::invalid_argument("MPS tensor entries must be finite.");
          }
        }
      },
      *_tensor);

  if (_physical_basis.size() != physical_dimension()) {
    throw std::invalid_argument(
        "MPS physical basis size must match the physical dimension.");
  }
  const auto bits = _physical_basis.front().bits_per_mode();
  if (bits != 1 && bits != 2) {
    throw std::invalid_argument(
        "MPS physical states require binary or spin-half configurations.");
  }
  std::array<bool, 4> seen{};
  for (const auto& state : _physical_basis) {
    if (state.bits_per_mode() != bits || state.capacity() == 0) {
      throw std::invalid_argument(
          "MPS physical states must share a nonempty configuration encoding.");
    }
    for (std::size_t mode = 1; mode < state.capacity(); ++mode) {
      if (state.get_mode_state(mode) != 0) {
        throw std::invalid_argument(
            "MPS physical states may occupy only their first mode.");
      }
    }
    const auto value = state.get_mode_state(0);
    if (value >= seen.size() || seen[value]) {
      throw std::invalid_argument("MPS physical states must be distinct.");
    }
    seen[value] = true;
  }
}

std::size_t MPSSite::_dimension(std::size_t slot) const {
  return std::visit(
      [slot](const auto& tensor) {
        return total_extent(tensor.extents()[slot]);
      },
      *_tensor);
}

std::size_t MPSSite::left_bond_dimension() const { return _dimension(0); }
std::size_t MPSSite::physical_dimension() const { return _dimension(1); }
std::size_t MPSSite::right_bond_dimension() const { return _dimension(2); }
bool MPSSite::is_complex() const { return _tensor->index() == 1; }

MPSSite::DenseMatrixVariant MPSSite::to_dense() const {
  const auto left = left_bond_dimension();
  const auto physical = physical_dimension();
  const auto right = right_bond_dimension();
  if (left > index_limit / physical || left * physical > index_limit / right) {
    throw std::overflow_error("Dense MPS site size exceeds Eigen::Index.");
  }
  return std::visit(
      [&](const auto& tensor) -> DenseMatrixVariant {
        using TensorType = std::decay_t<decltype(tensor)>;
        using Matrix =
            std::remove_const_t<typename TensorType::BlockPtr::element_type>;
        Matrix dense = Matrix::Zero(static_cast<Eigen::Index>(left * physical),
                                    static_cast<Eigen::Index>(right));
        std::array<std::unordered_map<SymmetryLabel, std::size_t>, 3> offsets;
        for (std::size_t slot = 0; slot < 3; ++slot) {
          offsets[slot] =
              sector_offsets(tensor.extents()[slot], _sector_orders[slot]);
        }
        for (const auto& [labels, block] : tensor.blocks()) {
          const auto local_left = tensor.extents()[0].at(labels[0]);
          const auto local_physical = tensor.extents()[1].at(labels[1]);
          for (std::size_t l = 0; l < local_left; ++l) {
            for (std::size_t p = 0; p < local_physical; ++p) {
              const auto row = (offsets[0].at(labels[0]) + l) * physical +
                               offsets[1].at(labels[1]) + p;
              dense.block(static_cast<Eigen::Index>(row),
                          static_cast<Eigen::Index>(offsets[2].at(labels[2])),
                          1, block->cols()) =
                  block->row(static_cast<Eigen::Index>(l * local_physical + p));
            }
          }
        }
        return dense;
      },
      *_tensor);
}

MPSContainer::MPSContainer(
    std::vector<SitePtr> sites, std::shared_ptr<Orbitals> orbitals,
    std::shared_ptr<const ParticleCount> total_num_particles,
    std::shared_ptr<const ParticleCount> active_num_particles,
    std::optional<std::size_t> orthogonality_center,
    std::vector<std::size_t> site_to_orbital_order,
    const std::optional<MatrixVariant>& one_rdm_spin_traced,
    const std::optional<MatrixVariant>& one_rdm_aa,
    const std::optional<MatrixVariant>& one_rdm_bb,
    const std::optional<VectorVariant>& two_rdm_spin_traced,
    const std::optional<VectorVariant>& two_rdm_aaaa,
    const std::optional<VectorVariant>& two_rdm_aabb,
    const std::optional<VectorVariant>& two_rdm_bbbb,
    const std::optional<SymmetryBlockedTensorVariant<2>>& active_one_rdm,
    const std::optional<SymmetryBlockedTensorVariant<4>>& active_two_rdm,
    const OrbitalEntropies& entropies)
    : WavefunctionContainer(
          one_rdm_spin_traced
              ? std::make_shared<MatrixVariant>(*one_rdm_spin_traced)
              : nullptr,
          two_rdm_spin_traced
              ? std::make_shared<VectorVariant>(*two_rdm_spin_traced)
              : nullptr,
          normalize_one_rdm(active_one_rdm, one_rdm_aa, one_rdm_bb),
          normalize_two_rdm(active_two_rdm, two_rdm_aaaa, two_rdm_aabb,
                            two_rdm_bbbb),
          entropies),
      _sites(std::move(sites)),
      _orbitals(std::move(orbitals)),
      _total_num_particles(std::move(total_num_particles)),
      _active_num_particles(std::move(active_num_particles)),
      _orthogonality_center(orthogonality_center),
      _site_to_orbital_order(std::move(site_to_orbital_order)) {
  if (_site_to_orbital_order.empty()) {
    _site_to_orbital_order.resize(num_sites());
    std::iota(_site_to_orbital_order.begin(), _site_to_orbital_order.end(),
              std::size_t{});
  }
  _validate();
  _validate_rdms();
  _validate_entropies();
  // Serialization keeps pair entropies as mutual information only.
  if (_entropies.two_orbital && !_entropies.mutual_information) {
    get_mutual_information();
  }
}

void MPSContainer::_validate_rdms() const {
  const auto n = static_cast<Eigen::Index>(num_sites());
  const auto symmetry = _orbitals->symmetries();
  if ((_active_one_rdm || _active_two_rdm) && symmetry &&
      symmetry->has_axis(AxisName::Spin) &&
      spin_channel_indices(_orbitals->active_indices(), axes::beta()).size() !=
          num_sites()) {
    throw std::invalid_argument(
        "MPS spin RDM dimensions must match both active spin spaces.");
  }
  auto validate_spin_spaces = [this](const auto& tensor) {
    for (std::size_t slot = 0; slot < tensor.extents().size(); ++slot) {
      const auto& symmetry = *tensor.symmetries()[slot];
      const auto& extents = tensor.extents()[slot];
      if (symmetry.axes().size() != 1 || !symmetry.has_axis(AxisName::Spin) ||
          symmetry.axis(AxisName::Spin).labels().size() != 2 ||
          extents.size() != 2 || !extents.contains(axes::alpha()) ||
          !extents.contains(axes::beta())) {
        throw std::invalid_argument(
            "MPS blocked RDMs require the supported alpha/beta index spaces.");
      }
      for (const auto& [label, extent] : extents) {
        if (extent != num_sites()) {
          throw std::invalid_argument(
              "MPS RDM extents must match the active sites.");
        }
      }
    }
  };
  auto validate_one = [n](const auto& matrix) {
    if (matrix.rows() != n || matrix.cols() != n || !matrix.allFinite()) {
      throw std::invalid_argument(
          "MPS 1-RDM must be finite and have shape (active sites, active "
          "sites).");
    }
  };
  if (_one_rdm_spin_traced) std::visit(validate_one, *_one_rdm_spin_traced);
  if (_active_one_rdm) {
    std::visit(
        [&](const auto& tensor) {
          validate_spin_spaces(tensor);
          if (tensor.num_blocks() != 2 ||
              !tensor.has_block({axes::alpha(), axes::alpha()}) ||
              !tensor.has_block({axes::beta(), axes::beta()})) {
            throw std::invalid_argument(
                "MPS requires both spin blocks of a supplied 1-RDM.");
          }
          for (const auto& [labels, block] : tensor.blocks())
            validate_one(*block);
        },
        *_active_one_rdm);
  }
  if (!_two_rdm_spin_traced && !_active_two_rdm) return;
  std::size_t size = 1;
  for (int axis = 0; axis < 4; ++axis) {
    if (num_sites() > index_limit / size) {
      throw std::invalid_argument("MPS 2-RDM size exceeds Eigen::Index.");
    }
    size *= num_sites();
  }
  auto validate_two = [size](const auto& vector) {
    if (vector.size() != static_cast<Eigen::Index>(size) ||
        !vector.allFinite()) {
      throw std::invalid_argument(
          "MPS 2-RDM must be finite and contain (active sites)^4 entries.");
    }
  };
  if (_two_rdm_spin_traced) std::visit(validate_two, *_two_rdm_spin_traced);
  if (_active_two_rdm) {
    std::visit(
        [&](const auto& tensor) {
          validate_spin_spaces(tensor);
          const typename std::decay_t<decltype(tensor)>::Labels bbaa{
              axes::beta(), axes::beta(), axes::alpha(), axes::alpha()};
          if ((tensor.num_blocks() != 3 && tensor.num_blocks() != 4) ||
              (tensor.num_blocks() == 4 && !tensor.has_block(bbaa)) ||
              !tensor.has_block({axes::alpha(), axes::alpha(), axes::alpha(),
                                 axes::alpha()}) ||
              !tensor.has_block(
                  {axes::alpha(), axes::alpha(), axes::beta(), axes::beta()}) ||
              !tensor.has_block(
                  {axes::beta(), axes::beta(), axes::beta(), axes::beta()})) {
            throw std::invalid_argument(
                "MPS requires all three spin blocks of a supplied 2-RDM.");
          }
          for (const auto& [labels, block] : tensor.blocks())
            validate_two(*block);
        },
        *_active_two_rdm);
  }
}

void MPSContainer::_validate_entropies() const {
  const auto n = static_cast<Eigen::Index>(num_sites());
  const auto& single = _entropies.single_orbital;
  if (single && (single->size() != n || !single->allFinite())) {
    throw std::invalid_argument(
        "MPS single-orbital entropies must be finite with one entry per "
        "active site.");
  }
  for (const auto* matrix :
       {&_entropies.two_orbital, &_entropies.mutual_information}) {
    if (*matrix && ((*matrix)->rows() != n || (*matrix)->cols() != n ||
                    !(*matrix)->allFinite())) {
      throw std::invalid_argument(
          "MPS two-orbital entropies and mutual information must be finite "
          "(active sites, active sites) matrices.");
    }
  }
  if (_entropies.two_orbital && !single) {
    throw std::invalid_argument(
        "MPS two-orbital entropies require single-orbital entropies.");
  }
}

void MPSContainer::_validate() const {
  if (_sites.empty() || !_orbitals) {
    throw std::invalid_argument(
        "MPS requires nonempty sites and a mode basis.");
  }
  for (const auto& site : _sites) {
    if (!site) {
      throw std::invalid_argument("MPS site pointers must not be null.");
    }
    if (site->is_complex() != _sites.front()->is_complex()) {
      throw std::invalid_argument("MPS sites must use one scalar type.");
    }
  }
  const ConfigurationSet mode_space(std::vector<Configuration>{}, _orbitals,
                                    Wavefunction::DEFAULT_SECTOR);
  if (mode_space.num_modes() != num_sites()) {
    throw std::invalid_argument("MPS must contain one site per active mode.");
  }
  if (_orthogonality_center && *_orthogonality_center >= num_sites()) {
    throw std::invalid_argument(
        "MPS orthogonality center must be a site index.");
  }
  if (_site_to_orbital_order.size() != num_sites()) {
    throw std::invalid_argument("MPS site order size must match its sites.");
  }
  auto sorted_order = _site_to_orbital_order;
  std::ranges::sort(sorted_order);
  for (std::size_t index = 0; index < num_sites(); ++index) {
    if (sorted_order[index] != index) {
      throw std::invalid_argument(
          "MPS site order must be a permutation of active-mode slots.");
    }
  }
  if (_sites.front()->left_bond_dimension() != 1 ||
      _sites.back()->right_bond_dimension() != 1) {
    throw std::invalid_argument("MPS outer bond dimensions must be one.");
  }
  for (std::size_t i = 0; i + 1 < num_sites(); ++i) {
    std::visit(
        [&](const auto& left, const auto& right) {
          if (*left.symmetries()[2] != *right.symmetries()[0] ||
              left.extents()[2] != right.extents()[0] ||
              _sites[i]->right_sector_order() !=
                  _sites[i + 1]->left_sector_order()) {
            throw std::invalid_argument(
                "Adjacent MPS sites have incompatible bond spaces.");
          }
        },
        _sites[i]->tensor(), _sites[i + 1]->tensor());
  }
}

std::size_t MPSContainer::max_bond_dimension() const {
  std::size_t maximum = 0;
  for (const auto& site : _sites) {
    // Every left bond is the right bond of the previous site. Edge sites have
    // bond dimension one.
    maximum = std::max(maximum, site->right_bond_dimension());
  }
  return maximum;
}

bool MPSContainer::is_complex() const { return _sites.front()->is_complex(); }

bool MPSContainer::_is_restricted_closed_shell() const { return false; }

std::shared_ptr<const MPSContainer::ParticleCount>
MPSContainer::total_num_particles() const {
  if (!_total_num_particles) {
    throw std::runtime_error("Total particle-count is not set.");
  }
  return _total_num_particles;
}

std::shared_ptr<const MPSContainer::ParticleCount>
MPSContainer::active_num_particles() const {
  if (!_active_num_particles) {
    throw std::runtime_error("Active particle-count is not set.");
  }
  return _active_num_particles;
}

MPSContainer::ScalarVariant MPSContainer::overlap(
    const WavefunctionContainer&) const {
  throw std::runtime_error(
      "overlap() is not implemented for MPS wavefunctions.");
}

MPSContainer::ScalarVariant MPSContainer::get_coefficient(
    const Configuration& det) const {
  if (det.capacity() < num_sites()) {
    throw std::invalid_argument(
        "Configuration has fewer modes than the MPS has sites.");
  }
  const auto bits = det.bits_per_mode();
  // Creation operators in chain order, labeled by determinant mode: slot o is
  // mode o for alpha or spinless states and num_sites() + o for beta.
  std::vector<std::size_t> created;
  std::vector<std::size_t> physical(num_sites());
  bool in_basis = true;
  for (std::size_t s = 0; s < num_sites(); ++s) {
    const auto& basis = _sites[s]->physical_basis();
    if (basis.front().bits_per_mode() != bits) {
      throw std::invalid_argument(
          "Configuration encoding differs from the MPS physical basis.");
    }
    const auto orbital = _site_to_orbital_order[s];
    const auto state = det.get_mode_state(orbital);
    const auto match =
        std::ranges::find_if(basis, [state](const Configuration& local) {
          return local.get_mode_state(0) == state;
        });
    if (match == basis.end()) {
      in_basis = false;
      continue;
    }
    physical[s] = static_cast<std::size_t>(match - basis.begin());
    if (bits == 1) {
      if (state != 0) created.push_back(orbital);
    } else {
      if (match->has_alpha_electron(0)) created.push_back(orbital);
      if (match->has_beta_electron(0)) created.push_back(num_sites() + orbital);
    }
  }
  for (std::size_t mode = num_sites(); mode < det.capacity(); ++mode) {
    if (det.get_mode_state(mode) != 0) in_basis = false;
  }
  if (!in_basis) {
    return is_complex() ? ScalarVariant(std::complex<double>(0.0, 0.0))
                        : ScalarVariant(0.0);
  }
  std::size_t inversions = 0;
  for (std::size_t i = 0; i < created.size(); ++i) {
    for (std::size_t j = i + 1; j < created.size(); ++j) {
      if (created[i] > created[j]) ++inversions;
    }
  }
  const double sign = inversions % 2 == 0 ? 1.0 : -1.0;
  if (is_complex()) {
    return sign * contract_amplitude<std::complex<double>>(_sites, physical);
  }
  return sign * contract_amplitude<double>(_sites, physical);
}

const ContainerTypes::VectorVariant&
MPSContainer::get_active_two_rdm_spin_traced() const {
  if (!_two_rdm_spin_traced && _active_two_rdm) {
    std::visit(
        [&](const auto& tensor) {
          const typename std::decay_t<decltype(tensor)>::Labels bbaa{
              axes::beta(), axes::beta(), axes::alpha(), axes::alpha()};
          if (tensor.has_block(bbaa)) {
            _two_rdm_spin_traced = std::make_shared<VectorVariant>(
                (tensor.block({axes::alpha(), axes::alpha(), axes::alpha(),
                               axes::alpha()}) +
                 tensor.block({axes::alpha(), axes::alpha(), axes::beta(),
                               axes::beta()}) +
                 tensor.block(bbaa) +
                 tensor.block(
                     {axes::beta(), axes::beta(), axes::beta(), axes::beta()}))
                    .eval());
          }
        },
        *_active_two_rdm);
  }
  return WavefunctionContainer::get_active_two_rdm_spin_traced();
}

double MPSContainer::norm() const {
  throw std::runtime_error("norm() is not implemented for MPS wavefunctions.");
}

std::shared_ptr<const SymmetryBlockedTensor<1>>
MPSContainer::total_orbital_occupations() const {
  const auto active = active_orbital_occupations();
  const auto sym = _orbitals->symmetries();
  const bool has_spin = sym && sym->has_axis(AxisName::Spin);
  const auto count =
      static_cast<Eigen::Index>(_orbitals->get_num_molecular_orbitals());
  auto embed = [&](const auto& spin) -> Eigen::VectorXd {
    Eigen::VectorXd result = Eigen::VectorXd::Zero(count);
    for (const auto index :
         spin_channel_indices(_orbitals->inactive_indices(), spin)) {
      result(static_cast<Eigen::Index>(index)) = 1.;
    }
    const auto indices =
        spin_channel_indices(_orbitals->active_indices(), spin);
    const auto& values =
        active->block({has_spin ? SymmetryLabel(spin) : SymmetryLabel{}});
    if (indices.size() != static_cast<std::size_t>(values.size())) {
      throw std::runtime_error(
          "MPS active orbital indices do not match the supplied 1-RDM.");
    }
    for (std::size_t i = 0; i < indices.size(); ++i) {
      result(static_cast<Eigen::Index>(indices[i])) =
          values(static_cast<Eigen::Index>(i));
    }
    return result;
  };
  return _make_orbital_occupations(
      embed(axes::alpha()),
      has_spin ? embed(axes::beta()) : Eigen::VectorXd::Zero(count).eval());
}

std::shared_ptr<const SymmetryBlockedTensor<1>>
MPSContainer::active_orbital_occupations() const {
  const auto sym = _orbitals->symmetries();
  if (sym && sym->has_axis(AxisName::Spin)) {
    if (!_active_one_rdm) {
      throw std::runtime_error(
          "MPS spin-resolved occupations require both spin blocks of the "
          "1-RDM.");
    }
    const auto [aa, bb] = get_active_one_rdm_spin_dependent();
    return _make_orbital_occupations(natural_occupations(aa),
                                     natural_occupations(bb));
  }
  const auto occupations =
      natural_occupations(get_active_one_rdm_spin_traced());
  return _make_orbital_occupations(occupations,
                                   Eigen::VectorXd::Zero(occupations.size()));
}

void MPSContainer::clear_caches() const {}
std::string MPSContainer::get_container_type() const { return "mps"; }

std::vector<std::string> MPSContainer::sectors() const {
  return {Wavefunction::DEFAULT_SECTOR};
}

std::shared_ptr<const Orbitals> MPSContainer::sector_basis(
    const std::string& name) const {
  if (name != Wavefunction::DEFAULT_SECTOR) {
    throw std::out_of_range("Unknown MPS wavefunction sector: " + name);
  }
  return _orbitals;
}

nlohmann::json MPSContainer::_metadata_to_json() const {
  nlohmann::json json;
  json["version"] = SERIALIZATION_VERSION;
  json["container_type"] = get_container_type();
  json["scalar"] = is_complex() ? "complex" : "real";
  json["total_num_particles"] = _total_num_particles
                                    ? _total_num_particles->to_json()
                                    : nlohmann::json(nullptr);
  json["active_num_particles"] = _active_num_particles
                                     ? _active_num_particles->to_json()
                                     : nlohmann::json(nullptr);
  json["orthogonality_center"] = _orthogonality_center
                                     ? nlohmann::json(*_orthogonality_center)
                                     : nlohmann::json(nullptr);
  json["site_to_orbital_order"] = _site_to_orbital_order;
  json["sites"] = nlohmann::json::array();
  for (const auto& site : _sites) {
    json["sites"].push_back(site_metadata(*site));
  }
  return json;
}

nlohmann::json MPSContainer::to_json() const {
  auto json = _metadata_to_json();
  json["orbitals"] = _orbitals->to_json();
  _serialize_rdms_to_json(json);
  _serialize_entropies_to_json(json);
  for (std::size_t i = 0; i < num_sites(); ++i) {
    json["sites"][i]["tensor"] =
        std::visit([](const auto& tensor) { return tensor.to_json(); },
                   _sites[i]->tensor());
  }
  return json;
}

std::unique_ptr<MPSContainer> MPSContainer::from_json(
    const nlohmann::json& json) {
  try {
    validate_metadata(json, SERIALIZATION_VERSION);
    std::vector<SitePtr> sites;
    for (const auto& site : json.at("sites")) {
      const auto& tensor = site.at("tensor");
      if (tensor.at("rank") != 3 || tensor.at("scalar") != json.at("scalar")) {
        throw std::invalid_argument(
            "MPS tensor rank or scalar type disagrees with its metadata.");
      }
      MPSSite::TensorPtr payload;
      if (json.at("scalar") == "complex") {
        payload = std::make_shared<const MPSSite::TensorVariant>(
            *SymmetryBlockedTensor<3, std::complex<double>>::from_json(tensor));
      } else {
        payload = std::make_shared<const MPSSite::TensorVariant>(
            *SymmetryBlockedTensor<3>::from_json(tensor));
      }
      sites.push_back(site_from_metadata(site, std::move(payload)));
    }
    auto result =
        mps_from_metadata(json, Orbitals::from_json(json.at("orbitals")),
                          std::move(sites), _entropies_from_json(json));
    result->_deserialize_rdms_from_json(json);
    result->_validate_rdms();
    return result;
  } catch (const nlohmann::json::exception& error) {
    throw std::runtime_error("Failed to parse MPSContainer from JSON: " +
                             std::string(error.what()));
  }
}

void MPSContainer::to_hdf5(H5::Group& group) const {
  try {
    const H5::StrType string_type(H5::PredType::C_S1, H5T_VARIABLE);
    const H5::DataSpace scalar_space(H5S_SCALAR);
    const std::string version = SERIALIZATION_VERSION;
    group.createAttribute("version", string_type, scalar_space)
        .write(string_type, version);
    group.createAttribute("container_type", string_type, scalar_space)
        .write(string_type, get_container_type());
    group.createDataSet("mps_metadata", string_type, scalar_space)
        .write(_metadata_to_json().dump(), string_type);
    auto orbitals = group.createGroup("orbitals");
    _orbitals->to_hdf5(orbitals);
    auto sites = group.createGroup("sites");
    for (std::size_t i = 0; i < num_sites(); ++i) {
      auto site = sites.createGroup(std::to_string(i));
      auto tensor = site.createGroup("tensor");
      std::visit([&](const auto& value) { value.to_hdf5(tensor); },
                 _sites[i]->tensor());
    }
    _serialize_rdms_to_hdf5(group);
    _serialize_entropies_to_hdf5(group);
  } catch (const H5::Exception& error) {
    throw std::runtime_error("Failed to write MPS HDF5: " +
                             error.getDetailMsg());
  }
}

std::unique_ptr<MPSContainer> MPSContainer::from_hdf5(H5::Group& group) {
  try {
    const H5::StrType string_type(H5::PredType::C_S1, H5T_VARIABLE);
    std::string version, type, payload;
    group.openAttribute("version").read(string_type, version);
    validate_serialization_version(SERIALIZATION_VERSION, version);
    group.openAttribute("container_type").read(string_type, type);
    if (type != "mps") {
      throw std::invalid_argument("HDF5 group does not contain an MPS.");
    }
    group.openDataSet("mps_metadata").read(payload, string_type);
    const auto json = nlohmann::json::parse(payload);
    validate_metadata(json, SERIALIZATION_VERSION);
    auto orbitals = group.openGroup("orbitals");
    auto site_group = group.openGroup("sites");
    std::vector<SitePtr> sites;
    for (std::size_t i = 0; i < json.at("sites").size(); ++i) {
      auto site = site_group.openGroup(std::to_string(i));
      auto tensor = site.openGroup("tensor");
      MPSSite::TensorPtr value;
      if (json.at("scalar") == "complex") {
        value = std::make_shared<const MPSSite::TensorVariant>(
            *SymmetryBlockedTensor<3, std::complex<double>>::from_hdf5(tensor));
      } else {
        value = std::make_shared<const MPSSite::TensorVariant>(
            *SymmetryBlockedTensor<3>::from_hdf5(tensor));
      }
      sites.push_back(
          site_from_metadata(json.at("sites").at(i), std::move(value)));
    }
    auto result =
        mps_from_metadata(json, Orbitals::from_hdf5(orbitals), std::move(sites),
                          _entropies_from_hdf5(group));
    result->_deserialize_rdms_from_hdf5(group);
    result->_validate_rdms();
    return result;
  } catch (const H5::Exception& error) {
    throw std::runtime_error("Failed to read MPS HDF5: " +
                             error.getDetailMsg());
  } catch (const nlohmann::json::exception& error) {
    throw std::runtime_error("Invalid MPS HDF5 metadata: " +
                             std::string(error.what()));
  }
}

void MPSContainer::hash_update(qdk::chemistry::utils::HashContext& ctx) const {
  WavefunctionContainer::hash_update(ctx);
  hash_value(ctx, get_container_type());
  hash_value(ctx, _orbitals->content_hash());
  hash_value(ctx, _total_num_particles);
  hash_value(ctx, _active_num_particles);
  hash_value(ctx, _orthogonality_center);
  hash_value(ctx, _site_to_orbital_order);
  hash_value(ctx, static_cast<std::uint64_t>(_sites.size()));
  for (const auto& site : _sites) {
    hash_value(ctx, site->tensor());
    for (const auto& order : site->sector_orders()) {
      hash_value(ctx, order);
    }
    hash_value(ctx, site->physical_basis());
  }
}

std::unique_ptr<WavefunctionContainer> MPSContainer::clone() const {
  return std::make_unique<MPSContainer>(*this);
}

}  // namespace qdk::chemistry::data
