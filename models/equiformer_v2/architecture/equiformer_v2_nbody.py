import math

import torch
import torch.nn as nn

from utils.build_fully_connected_graph import build_graph_with_knn

from .base_model import BaseModel
from .edge_rot_mat import init_edge_rot_mat
from .gaussian_rbf import GaussianRadialBasisLayer
from .input_block import EdgeDegreeEmbedding
from .layer_norm import (
    EquivariantLayerNormArray,
    EquivariantLayerNormArraySphericalHarmonics,
    EquivariantRMSNormArraySphericalHarmonics,
    EquivariantRMSNormArraySphericalHarmonicsV2,
    get_normalization_layer,
)
from .module_list import ModuleListInfo
from .radial_function import RadialFunction
from .so3 import (
    CoefficientMappingModule,
    SO3_Embedding,
    SO3_Grid,
    SO3_LinearV2,
    SO3_Rotation,
)
from .transformer_block import (
    FeedForwardNetwork,
    SO2EquivariantGraphAttention,
    TransBlockV2,
)
from .utils import GaussianSmearing

# Statistics of IS2RE 100K
_AVG_DEGREE = 23.395238876342773  # IS2RE: 100k, max_radius = 5, max_neighbors = 100


class ExponentialDecayFunction(torch.nn.Module):
    def __init__(self, scale=1.0):
        super(ExponentialDecayFunction, self).__init__()
        # `scale` controls the rate of decay
        self.scale = nn.Parameter(torch.tensor(scale))
        projection_dim = 1024
        self.projection = nn.Linear(1, projection_dim)

    def forward(self, distances):
        # Ensure distances are non-negative
        distances = distances.abs()
        # Compute the exponential decay
        exp = torch.exp(-self.scale * distances)
        projected = self.projection(exp)
        return projected


# TODO: consider using conditional gradients: https://github.com/Open-Catalyst-Project/ocp/blob/9108a87ce383b2982c24eff4178632f01fecb63e/ocpmodels/common/utils.py#L129C1-L143C21
class EquiformerV2_nbody(BaseModel):
    """
    Equiformer with graph attention built upon SO(2) convolution and feedforward network built upon S2 activation

    Args:
        use_pbc (bool):         Use periodic boundary conditions
        regress_forces (bool):  Compute forces
        otf_graph (bool):       Compute graph On The Fly (OTF)
        max_neighbors (int):    Maximum number of neighbors per atom
        max_radius (float):     Maximum distance between neighboring atoms in Angstroms
        max_num_elements (int): Maximum atomic number

        num_layers (int):             Number of layers in the GNN
        sphere_channels (int):        Number of spherical channels (one set per resolution)
        attn_hidden_channels (int): Number of hidden channels used during SO(2) graph attention
        num_heads (int):            Number of attention heads
        attn_alpha_head (int):      Number of channels for alpha vector in each attention head
        attn_value_head (int):      Number of channels for value vector in each attention head
        ffn_hidden_channels (int):  Number of hidden channels used during feedforward network
        norm_type (str):            Type of normalization layer (['layer_norm', 'layer_norm_sh', 'rms_norm_sh'])

        lmax_list (int):              List of maximum degree of the spherical harmonics (1 to 10)
        mmax_list (int):              List of maximum order of the spherical harmonics (0 to lmax)
        grid_resolution (int):        Resolution of SO3_Grid

        num_sphere_samples (int):     Number of samples used to approximate the integration of the sphere in the output blocks

        edge_chanels n(int):                Number of channels for the edge invariant features
        use_atom_edge_embedding (bool):     Whether to use atomic embedding along with relative distance for edge scalar features
        share_atom_edge_embedding (bool):   Whether to share `atom_edge_embedding` across all blocks
        use_m_share_rad (bool):             Whether all m components within a type-L vector of one channel share radial function weights
        distance_function ("gaussian", "sigmoid", "linearsigmoid", "silu"):  Basis function used for distances

        attn_activation (str):      Type of activation function for SO(2) graph attention
        use_s2_act_attn (bool):     Whether to use attention after S2 activation. Otherwise, use the same attention as Equiformer
        use_attn_renorm (bool):     Whether to re-normalize attention weights
        ffn_activation (str):       Type of activation function for feedforward network
        use_gate_act (bool):        If `True`, use gate activation. Otherwise, use S2 activation
        use_grid_mlp (bool):        If `True`, use projecting to grids and performing MLPs for FFNs.
        use_sep_s2_act (bool):      If `True`, use separable S2 activation when `use_gate_act` is False.

        alpha_drop (float):         Dropout rate for attention weights
        drop_path_rate (float):     Drop path rate
        proj_drop (float):          Dropout rate for outputs of attention and FFN in Transformer blocks

        weight_init (str):          ['normal', 'uniform'] initialization of weights of linear layers except those in radial functions
    """

    def __init__(
        self,
        device,
        use_pbc=False,
        regress_forces=True,
        otf_graph=True,
        max_neighbors=5,
        max_radius=4096,  # TODO: we can afford this with a small number of atoms. workaround to max radius returning empty edge index undefined behavior: if torch.min(edge_vec_0_distance) < 0.0001: RuntimeError: min(): Expected reduction dim to be specified for input.numel() == 0. Specify the reduction dim with the 'dim' argument.
        max_num_elements=90,
        num_layers=12,
        attn_hidden_channels=128,
        sphere_channels=128,
        num_heads=8,
        attn_alpha_channels=32,
        attn_value_channels=16,
        ffn_hidden_channels=512,
        norm_type="rms_norm_sh",
        lmax_list=[6],
        mmax_list=[2],
        grid_resolution=None,
        num_sphere_samples=128,
        edge_channels=128,
        use_atom_edge_embedding=True,
        share_atom_edge_embedding=False,
        use_m_share_rad=False,
        distance_function="projection",
        num_distance_basis=512,
        attn_activation="scaled_silu",
        use_s2_act_attn=False,
        use_attn_renorm=True,
        ffn_activation="scaled_silu",
        use_gate_act=False,
        use_grid_mlp=False,
        use_sep_s2_act=True,
        alpha_drop=0.1,
        drop_path_rate=0.05,
        proj_drop=0.0,
        weight_init="normal",
    ):
        super().__init__()

        self.use_pbc = use_pbc
        self.regress_forces = regress_forces
        self.otf_graph = otf_graph
        self.max_neighbors = max_neighbors
        self.max_radius = max_radius
        self.cutoff = max_radius
        self.max_num_elements = max_num_elements

        self.num_layers = num_layers
        self.sphere_channels = sphere_channels
        self.attn_hidden_channels = attn_hidden_channels
        self.num_heads = num_heads
        self.attn_alpha_channels = attn_alpha_channels
        self.attn_value_channels = attn_value_channels
        self.ffn_hidden_channels = ffn_hidden_channels
        self.norm_type = norm_type

        self.lmax_list = lmax_list
        self.mmax_list = mmax_list
        self.grid_resolution = grid_resolution

        self.num_sphere_samples = num_sphere_samples

        self.edge_channels = edge_channels
        self.use_atom_edge_embedding = use_atom_edge_embedding
        self.share_atom_edge_embedding = share_atom_edge_embedding
        if self.share_atom_edge_embedding:
            assert self.use_atom_edge_embedding
            self.block_use_atom_edge_embedding = False
        else:
            self.block_use_atom_edge_embedding = self.use_atom_edge_embedding
        self.use_m_share_rad = use_m_share_rad
        self.distance_function = distance_function
        self.num_distance_basis = num_distance_basis

        self.attn_activation = attn_activation
        self.use_s2_act_attn = use_s2_act_attn
        self.use_attn_renorm = use_attn_renorm
        self.ffn_activation = ffn_activation
        self.use_gate_act = use_gate_act
        self.use_grid_mlp = use_grid_mlp
        self.use_sep_s2_act = use_sep_s2_act

        self.alpha_drop = alpha_drop
        self.drop_path_rate = drop_path_rate
        self.proj_drop = proj_drop

        self.weight_init = weight_init
        assert self.weight_init in ["normal", "uniform"]

        # Device will be determined from input tensors, not cached
        # self.device = device

        self.grad_forces = False
        self.num_resolutions = len(self.lmax_list)
        self.sphere_channels_all = self.num_resolutions * self.sphere_channels

        # Weights for message initialization
        self.sphere_embedding = nn.Embedding(
            self.max_num_elements, self.sphere_channels_all
        )

        # Velocity embedding for type-1 vectors (should output 3 components, each with sphere_channels)
        self.velocity_embedding = nn.Linear(3, 3 * self.sphere_channels)

        # self.vel_embedding = SO3_Embedding(
        #     80,
        #     self.lmax_list,
        #     self.sphere_channels,
        # )

        # Initialize the function used to measure the distances between atoms
        assert self.distance_function in ["gaussian", "projection", "exponential_decay"]
        projection_dim = 1024
        if self.distance_function == "gaussian":
            self.distance_expansion = GaussianSmearing(
                0.0,
                self.cutoff,
                projection_dim,
                2.0,
            )
            # self.distance_expansion = GaussianRadialBasisLayer(num_basis=self.num_distance_basis, cutoff=self.max_radius)
        elif self.distance_function == "projection":
            self.distance_expansion = nn.Linear(1, projection_dim)

        elif self.distance_function == "exponential_decay":
            self.distance_expansion = ExponentialDecayFunction()

        else:
            raise ValueError

        # Initialize the sizes of radial functions (input channels and 2 hidden channels)
        # Assuming only scalar distance is used as the edge feature
        self.edge_channels_list = [projection_dim] + [self.edge_channels] * 2

        # Initialize atom edge embedding
        if self.share_atom_edge_embedding and self.use_atom_edge_embedding:
            self.source_embedding = nn.Embedding(
                self.max_num_elements, self.edge_channels_list[-1]
            )
            self.target_embedding = nn.Embedding(
                self.max_num_elements, self.edge_channels_list[-1]
            )
            self.edge_channels_list[0] = (
                self.edge_channels_list[0] + 2 * self.edge_channels_list[-1]
            )
        else:
            self.source_embedding, self.target_embedding = None, None

        # Initialize the module that compute WignerD matrices and other values for spherical harmonic calculations
        self.SO3_rotation = nn.ModuleList()
        for i in range(self.num_resolutions):
            self.SO3_rotation.append(SO3_Rotation(self.lmax_list[i]))

        # Initialize conversion between degree l and order m layouts
        self.mappingReduced = CoefficientMappingModule(self.lmax_list, self.mmax_list)

        # Initialize the transformations between spherical and grid representations
        self.SO3_grid = ModuleListInfo(
            "({}, {})".format(max(self.lmax_list), max(self.lmax_list))
        )
        for l in range(max(self.lmax_list) + 1):
            SO3_m_grid = nn.ModuleList()
            for m in range(max(self.lmax_list) + 1):
                SO3_m_grid.append(
                    SO3_Grid(
                        l, m, resolution=self.grid_resolution, normalization="component"
                    )
                )
            self.SO3_grid.append(SO3_m_grid)

        # Edge-degree embedding
        self.edge_degree_embedding = EdgeDegreeEmbedding(
            self.sphere_channels,
            self.lmax_list,
            self.mmax_list,
            self.SO3_rotation,
            self.mappingReduced,
            self.max_num_elements,
            self.edge_channels_list,
            self.block_use_atom_edge_embedding,
            rescale_factor=_AVG_DEGREE,
        )

        # Initialize the blocks for each layer of EquiformerV2
        self.blocks = nn.ModuleList()
        for i in range(self.num_layers):
            block = TransBlockV2(
                self.sphere_channels,
                self.attn_hidden_channels,
                self.num_heads,
                self.attn_alpha_channels,
                self.attn_value_channels,
                self.ffn_hidden_channels,
                self.sphere_channels,
                self.lmax_list,
                self.mmax_list,
                self.SO3_rotation,
                self.mappingReduced,
                self.SO3_grid,
                self.max_num_elements,
                self.edge_channels_list,
                self.block_use_atom_edge_embedding,
                self.use_m_share_rad,
                self.attn_activation,
                self.use_s2_act_attn,
                self.use_attn_renorm,
                self.ffn_activation,
                self.use_gate_act,
                self.use_grid_mlp,
                self.use_sep_s2_act,
                self.norm_type,
                self.alpha_drop,
                self.drop_path_rate,
                self.proj_drop,
            )
            self.blocks.append(block)

        # Output blocks for energy and forces
        self.norm = get_normalization_layer(
            self.norm_type, lmax=max(self.lmax_list), num_channels=self.sphere_channels
        )
        self.energy_block = FeedForwardNetwork(
            self.sphere_channels,
            self.ffn_hidden_channels,
            1,
            self.lmax_list,
            self.mmax_list,
            self.SO3_grid,
            self.ffn_activation,
            self.use_gate_act,
            self.use_grid_mlp,
            self.use_sep_s2_act,
        )  # TODO: remove or put under a flag
        if self.regress_forces:
            self.force_block = SO2EquivariantGraphAttention(
                self.sphere_channels,
                self.attn_hidden_channels,
                self.num_heads,
                self.attn_alpha_channels,
                self.attn_value_channels,
                2,
                self.lmax_list,
                self.mmax_list,
                self.SO3_rotation,
                self.mappingReduced,
                self.SO3_grid,
                self.max_num_elements,
                self.edge_channels_list,
                self.block_use_atom_edge_embedding,
                self.use_m_share_rad,
                self.attn_activation,
                self.use_s2_act_attn,
                self.use_attn_renorm,
                self.use_gate_act,
                self.use_sep_s2_act,
                alpha_drop=0.0,
            )
        self.vel_block = SO2EquivariantGraphAttention(
            self.sphere_channels,
            self.attn_hidden_channels,
            self.num_heads,
            self.attn_alpha_channels,
            self.attn_value_channels,
            1,
            self.lmax_list,
            self.mmax_list,
            self.SO3_rotation,
            self.mappingReduced,
            self.SO3_grid,
            self.max_num_elements,
            self.edge_channels_list,
            self.block_use_atom_edge_embedding,
            self.use_m_share_rad,
            self.attn_activation,
            self.use_s2_act_attn,
            self.use_attn_renorm,
            self.use_gate_act,
            self.use_sep_s2_act,
            alpha_drop=0.0,
        )

        self.apply(self._init_weights)
        self.apply(self._uniform_init_rad_func_linear_weights)

    # TODO: consider using conditional gradients: https://github.com/Open-Catalyst-Project/ocp/blob/9108a87ce383b2982c24eff4178632f01fecb63e/ocpmodels/common/utils.py#L129C1-L143C21
    def forward(self, data, batch=None):
        # Handle case where batch is provided as part of data (PyTorch Geometric style)
        if batch is None and hasattr(data, "batch"):
            batch = data.batch
        elif batch is None:
            # Create proper batch indices based on the actual data structure
            if hasattr(data, "pos"):
                # Extract batch info from the data structure
                # Assuming each sample has num_atoms nodes, we need to create batch indices
                total_nodes = data.pos.shape[0]
                # Try to infer batch size from the data
                batch = torch.zeros(
                    total_nodes, dtype=torch.long, device=data.pos.device
                )
            else:
                batch = None

        # Extract data based on PyTorch Geometric format
        if hasattr(data, "pos"):
            # PyTorch Geometric format
            pos = data.pos
            vel = data.vel if hasattr(data, "vel") else torch.zeros_like(pos)
            # For n-body simulations, use a dummy atomic number (e.g., hydrogen = 1)
            # Clamp to valid range [0, max_num_elements-1]
            if hasattr(data, "x") and data.x.shape[1] > 0:
                charges = torch.clamp(data.x[:, 0], 0, self.max_num_elements - 1)
            else:
                # Use atomic number 1 (hydrogen) for all particles in n-body simulations
                charges = torch.ones(pos.shape[0], dtype=torch.long, device=pos.device)
            data_tuple = (pos, vel, None, charges, None)
        else:
            # Original tuple format
            data_tuple = data

        return self._forward_internal(data_tuple, batch)

    def _forward_internal(self, data, batch):
        loc_frame_0, vel_frame_0, edge_attr, charges, _ = data
        # Extract relevant information from the input data
        pos = loc_frame_0
        vel = vel_frame_0
        atomic_numbers = charges.reshape(-1).int()
        num_atoms = len(atomic_numbers)

        # (
        #     edge_index,
        #     edge_distance,
        #     edge_distance_vec,
        # ) = self.generate_graph(data, batch)

        # For n-body simulations, we typically want all particles to interact
        # Use build_fully_connected_graph for full interactions
        batch_size = max(batch) + 1

        # Infer batch_size from data structure
        # For n-body simulations, we typically have num_atoms particles per simulation
        # Default to 5 particles per simulation if not specified
        particles_per_sim = (
            num_atoms // batch_size
        )  # This should match the dataset configuration - use integer division
        edge_index = build_graph_with_knn(
            pos,
            batch_size,
            int(particles_per_sim),
            pos.device,
            int(particles_per_sim - 1),
        )

        # Alternative: Use k-NN for larger simulations where full connectivity is prohibitive
        # from utils.build_fully_connected_graph import build_graph_with_knn
        # k = min(50, int(num_atoms / batch_size) - 1)  # Adjust k based on your needs
        # edge_index = build_graph_with_knn(
        #     pos, batch_size, int(num_atoms / batch_size), pos.device, num_neighbors=k
        # )

        j, i = edge_index
        edge_distance_vec = pos[j] - pos[i]
        edge_distance = edge_distance_vec.norm(dim=-1)

        ###############################################################
        # Initialize data structures
        ###############################################################

        # Compute 3x3 rotation matrix per edge
        edge_rot_mat = self._init_edge_rot_mat(edge_distance_vec)

        # Initialize the WignerD matrices and other values for spherical harmonic calculations
        for i in range(self.num_resolutions):
            self.SO3_rotation[i].set_wigner(edge_rot_mat)

        ###############################################################
        # Initialize node embeddings
        ###############################################################

        # Initialize per-node representations using an atomic number-based embedding
        x = SO3_Embedding(
            num_atoms, self.lmax_list, self.sphere_channels, pos.device, pos.dtype
        )

        # vel_embedding = SO3_Embedding(3, self.lmax_list, self.sphere_channels, self.device, vel.dtype)

        # vel_embedding.set_embedding(velocities_expanded)

        offset_res = 0
        offset = 0
        sphere_emb = self.sphere_embedding(atomic_numbers)  # (N, sphere_channels_all)

        # Properly embed velocities as type-1 vectors
        vel_embedded = self.velocity_embedding(vel)  # (N, 3 * sphere_channels)
        vel_embedded = vel_embedded.reshape(
            -1, 3, self.sphere_channels
        )  # (N, 3, sphere_channels)

        # Initialize the l = 0, m = 0 coefficients for each resolution
        for i in range(self.num_resolutions):
            # Add scalar embedding to type-0 (l=0, m=0)
            if self.num_resolutions == 1:
                x.embedding[:, offset_res, :] = (
                    x.embedding[:, offset_res, :] + sphere_emb
                )
            else:
                x.embedding[:, offset_res, :] = (
                    x.embedding[:, offset_res, :]
                    + sphere_emb[:, offset : offset + self.sphere_channels]
                )

            # Add velocity embedding to type-1 vectors (l=1, m=-1,0,1)
            # Only add to the first resolution to avoid duplication
            if i == 0:
                x.embedding[:, offset_res + 1 : offset_res + 4, :] = (
                    x.embedding[:, offset_res + 1 : offset_res + 4, :] + vel_embedded
                )

            offset += self.sphere_channels
            offset_res += int((self.lmax_list[i] + 1) ** 2)

            x.embedding = x.embedding.to(pos.device)

        # Edge encoding (distance and atom edge)
        edge_distance = edge_distance.unsqueeze(1)
        edge_distance = self.distance_expansion(edge_distance)
        if self.share_atom_edge_embedding and self.use_atom_edge_embedding:
            source_element = atomic_numbers[edge_index[0]]  # Source atom atomic number
            target_element = atomic_numbers[edge_index[1]]  # Target atom atomic number
            source_embedding = self.source_embedding(source_element)
            target_embedding = self.target_embedding(target_element)
            edge_distance = torch.cat(
                (edge_distance, source_embedding, target_embedding), dim=1
            )

        # Edge-degree embedding
        edge_degree = self.edge_degree_embedding(
            atomic_numbers.long(), edge_distance, edge_index
        )
        x.embedding = x.embedding + edge_degree.embedding

        ###############################################################
        # Update spherical node embeddings
        ###############################################################

        for i in range(self.num_layers):
            x = self.blocks[i](
                x, atomic_numbers, edge_distance, edge_index, batch=batch
            )

        # Final layer norm
        x.embedding = self.norm(x.embedding)

        ###############################################################
        # Position and velocity prediction
        ###############################################################

        pred = self.force_block(x, atomic_numbers, edge_distance, edge_index)

        pred_delta_pos = pred.embedding[..., 0]
        pred_vel = pred.embedding[..., 1]

        pred_delta_pos = pred_delta_pos.narrow(1, 1, 3)
        pred_vel = pred_vel.narrow(1, 1, 3)
        pred_delta_pos = pred_delta_pos.view(-1, 3)  # (num_atoms, 3)
        pred_vel = pred_vel.view(-1, 3)

        # Return position deltas and velocities as expected by the trainer
        return torch.cat((pred_delta_pos, pred_vel), dim=1)

    # Initialize the edge rotation matrix
    def _init_edge_rot_mat(self, edge_distance_vec):
        return init_edge_rot_mat(edge_distance_vec)

    @property
    def num_params(self):
        return sum(p.numel() for p in self.parameters())

    def _init_weights(self, m):
        if isinstance(m, torch.nn.Linear) or isinstance(m, SO3_LinearV2):
            if m.bias is not None:
                torch.nn.init.constant_(m.bias, 0)
            if self.weight_init == "normal":
                std = 1 / math.sqrt(m.in_features)
                torch.nn.init.normal_(m.weight, 0, std)

        elif isinstance(m, torch.nn.LayerNorm):
            torch.nn.init.constant_(m.bias, 0)
            torch.nn.init.constant_(m.weight, 1.0)

    def _uniform_init_rad_func_linear_weights(self, m):
        if isinstance(m, RadialFunction):
            m.apply(self._uniform_init_linear_weights)

    def _uniform_init_linear_weights(self, m):
        if isinstance(m, torch.nn.Linear):
            if m.bias is not None:
                torch.nn.init.constant_(m.bias, 0)
            std = 1 / math.sqrt(m.in_features)
            torch.nn.init.uniform_(m.weight, -std, std)

    @torch.jit.ignore
    def no_weight_decay(self):
        no_wd_list = []
        named_parameters_list = [name for name, _ in self.named_parameters()]
        for module_name, module in self.named_modules():
            if (
                isinstance(module, torch.nn.Linear)
                or isinstance(module, SO3_LinearV2)
                or isinstance(module, torch.nn.LayerNorm)
                or isinstance(module, EquivariantLayerNormArray)
                or isinstance(module, EquivariantLayerNormArraySphericalHarmonics)
                or isinstance(module, EquivariantRMSNormArraySphericalHarmonics)
                or isinstance(module, EquivariantRMSNormArraySphericalHarmonicsV2)
                or isinstance(module, GaussianRadialBasisLayer)
            ):
                for parameter_name, _ in module.named_parameters():
                    if isinstance(module, torch.nn.Linear) or isinstance(
                        module, SO3_LinearV2
                    ):
                        if "weight" in parameter_name:
                            continue
                    global_parameter_name = module_name + "." + parameter_name
                    assert global_parameter_name in named_parameters_list
                    no_wd_list.append(global_parameter_name)
        return set(no_wd_list)

    def get_serializable_attributes(self):
        return {
            "use_pbc": self.use_pbc,
            "regress_forces": self.regress_forces,
            "otf_graph": self.otf_graph,
            "max_neighbors": self.max_neighbors,
            "max_radius": self.max_radius,
            "max_num_elements": self.max_num_elements,
            "num_layers": self.num_layers,
            "sphere_channels": self.sphere_channels,
            "attn_hidden_channels": self.attn_hidden_channels,
            "num_heads": self.num_heads,
            "attn_alpha_channels": self.attn_alpha_channels,
            "attn_value_channels": self.attn_value_channels,
            "ffn_hidden_channels": self.ffn_hidden_channels,
            "norm_type": self.norm_type,
            "lmax_list": self.lmax_list,
            "mmax_list": self.mmax_list,
            "grid_resolution": self.grid_resolution,
            "num_sphere_samples": self.num_sphere_samples,
            "edge_channels": self.edge_channels,
            "use_atom_edge_embedding": self.use_atom_edge_embedding,
            "share_atom_edge_embedding": self.share_atom_edge_embedding,
            "use_m_share_rad": self.use_m_share_rad,
            "distance_function": self.distance_function,
            "attn_activation": self.attn_activation,
            "use_s2_act_attn": self.use_s2_act_attn,
            "use_attn_renorm": self.use_attn_renorm,
            "ffn_activation": self.ffn_activation,
            "use_gate_act": self.use_gate_act,
            "use_grid_mlp": self.use_grid_mlp,
            "use_sep_s2_act": self.use_sep_s2_act,
            "alpha_drop": self.alpha_drop,
            "drop_path_rate": self.drop_path_rate,
            "proj_drop": self.proj_drop,
            "weight_init": self.weight_init,
        }

    def get_model_size(self):
        """Return model size for learning rate scheduling"""
        return self.sphere_channels
