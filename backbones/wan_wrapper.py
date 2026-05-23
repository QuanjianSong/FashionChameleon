import os

import types
from typing import List, Optional
import torch

from utils.scheduler import SchedulerInterface, FlowMatchScheduler
from .wan22.modules.tokenizers import HuggingfaceTokenizer
from .wan22.modules.t5 import umt5_xxl

from .wan22.modules.vae2_2 import _video_vae_2_2
from .wan22.modules.model import Wan22Model
# from .wan22.modules.causal_model import CausalWan22Model


class WanTextEncoder(torch.nn.Module):
    def __init__(self, model_name="./wan_models/Wan2.2-TI2V-5B") -> None:
        super().__init__()
        self.model_name = model_name

        self.text_encoder = umt5_xxl(
            encoder_only=True,
            return_tokenizer=False,
            dtype=torch.float32,
            device=torch.device('cpu')
        ).eval().requires_grad_(False)
        self.text_encoder.load_state_dict(
            torch.load(os.path.join(self.model_name, "models_t5_umt5-xxl-enc-bf16.pth"), map_location='cpu', weights_only=False)
        )

        self.tokenizer = HuggingfaceTokenizer(name=os.path.join(self.model_name, "google/umt5-xxl"), seq_len=512, clean='whitespace')

    @property
    def device(self):
        # Assume we are always on GPU
        return torch.cuda.current_device()

    def forward(self, text_prompts: List[str]) -> dict:
        ids, mask = self.tokenizer(
            text_prompts, return_mask=True, add_special_tokens=True)
        ids = ids.to(self.device)
        mask = mask.to(self.device)
        seq_lens = mask.gt(0).sum(dim=1).long()
        context = self.text_encoder(ids, mask)

        for u, v in zip(context, seq_lens):
            u[v:] = 0.0  # set padding to 0.0

        return {
            "prompt_embeds": context
        }


class WanVAEWrapper(torch.nn.Module):
    def __init__(self, model_name="./wan_models/Wan2.2-TI2V-5B"):
        super().__init__()
        self.model_name = model_name

        if "2.2" in model_name and "5B" in model_name:
            self.mean = torch.tensor([-0.2289,-0.0052,-0.1323,-0.2339,-0.2799,0.0174,0.1838,0.1557,-0.1382,0.0542,0.2813,0.0891,0.1570,-0.0098,
                    0.0375,-0.1825,-0.2246,-0.1207,-0.0698,0.5109,0.2665,-0.2108,-0.2158,0.2502,-0.2055,-0.0322,0.1109,0.1567,-0.0729,0.0899,-0.2799,
                    -0.1230,-0.0313,-0.1649,0.0117,0.0723,-0.2839,-0.2083,-0.0520,0.3748,0.0152,0.1957,0.1433,-0.2944,0.3573,-0.0548,-0.1681,-0.0667,
                ],
                dtype=torch.float32,
            )
            self.std = torch.tensor([
                0.4765,1.0364,0.4514,1.1677,0.5313,0.4990,0.4818,0.5013,0.8158,1.0344,0.5894,1.0901,0.6885,0.6165,0.8454,0.4978,
                0.5759,0.3523,0.7135,0.6804,0.5833,1.4146,0.8986,0.5659,0.7069,0.5338,0.4889,0.4917,0.4069,0.4999,0.6866,0.4093,
                0.5709,0.6065,0.6415,0.4944,0.5726,1.2042,0.5458,1.6887,0.3971,1.0600,0.3943,0.5537,0.5444,0.4089,0.7468,0.7744,
                ],
                dtype=torch.float32,
            )
            self.model = (
                _video_vae_2_2(
                    pretrained_path=os.path.join(self.model_name, "Wan2.2_VAE.pth"),
                    z_dim=48,
                    dim=160,
                    dim_mult=[1, 2, 4, 4],
                    temperal_downsample=[False, True, True],
                )
                .eval()
                .requires_grad_(False)
            )
        else:
            raise NotImplementedError

    def encode_to_latent(self, pixel: torch.Tensor) -> torch.Tensor:
        # pixel: [batch_size, num_channels, num_frames, height, width]
        device, dtype = pixel.device, pixel.dtype
        scale = [self.mean.to(device=device, dtype=dtype),
                 1.0 / self.std.to(device=device, dtype=dtype)]

        output = [
            self.model.encode(u.unsqueeze(0), scale).float().squeeze(0)
            for u in pixel
        ]
        output = torch.stack(output, dim=0)
        # from [batch_size, num_channels, num_frames, height, width]
        # to [batch_size, num_frames, num_channels, height, width]
        output = output.permute(0, 2, 1, 3, 4)

        return output

    def decode_to_pixel(self, latent: torch.Tensor, use_cache: bool = False) -> torch.Tensor:
        # from [batch_size, num_frames, num_channels, height, width]
        # to [batch_size, num_channels, num_frames, height, width]
        zs = latent.permute(0, 2, 1, 3, 4)
        if use_cache:
            assert latent.shape[0] == 1, "Batch size must be 1 when using cache"

        device, dtype = latent.device, latent.dtype
        scale = [self.mean.to(device=device, dtype=dtype),
                 1.0 / self.std.to(device=device, dtype=dtype)]

        if use_cache:
            decode_function = self.model.cached_decode
        else:
            decode_function = self.model.decode

        output = []
        for u in zs:
            output.append(decode_function(u.unsqueeze(0), scale).float().clamp_(-1, 1).squeeze(0))
        output = torch.stack(output, dim=0)
        # from [batch_size, num_channels, num_frames, height, width]
        # to [batch_size, num_frames, num_channels, height, width]
        output = output.permute(0, 2, 1, 3, 4)

        return output


class WanDiffusionWrapper(torch.nn.Module):
    def __init__(
            self,
            model_name="./wan_models/Wan2.2-TI2V-5B",
            timestep_shift=5.0,
            is_causal=False,
            seq_list=[1, 23, 48, 80, 44],
            local_attn_size=-1,
            sink_size=0,
    ):
        super().__init__()
        self.model_name = model_name

        if is_causal:
            if "2.2" in self.model_name and '5B' in self.model_name:
                self.model = CausalWan22Model.from_pretrained(model_name, local_attn_size=local_attn_size, sink_size=sink_size)
            else:
                raise NotImplementedError
        else:
            if "2.2" in self.model_name and '5B' in self.model_name:
                self.model = Wan22Model.from_pretrained(model_name)
            else:
                raise NotImplementedError
        self.seq_len = int(seq_list[1] * seq_list[-2] / self.model.patch_size[-2] * seq_list[-1] / self.model.patch_size[-1])
        self.model.eval()

        # For non-causal diffusion, all frames share the same timestep
        self.uniform_timestep = not is_causal

        self.scheduler = FlowMatchScheduler(
            shift=timestep_shift, sigma_min=0.0, extra_one_step=True
        )
        self.scheduler.set_timesteps(1000, training=True)
        
        self.post_init()

    def enable_gradient_checkpointing(self) -> None:
        self.model.enable_gradient_checkpointing()

    def _convert_flow_pred_to_x0(self, flow_pred: torch.Tensor, xt: torch.Tensor, timestep: torch.Tensor) -> torch.Tensor:
        """
        Convert flow matching's prediction to x0 prediction.
        flow_pred: the prediction with shape [B, C, H, W]
        xt: the input noisy data with shape [B, C, H, W]
        timestep: the timestep with shape [B]

        pred = noise - x0
        x_t = (1-sigma_t) * x0 + sigma_t * noise
        we have x0 = x_t - sigma_t * pred
        see derivations https://chatgpt.com/share/67bf8589-3d04-8008-bc6e-4cf1a24e2d0e
        """
        # use higher precision for calculations
        original_dtype = flow_pred.dtype
        flow_pred, xt, sigmas, timesteps = map(
            lambda x: x.double().to(flow_pred.device), [flow_pred, xt,
                                                        self.scheduler.sigmas,
                                                        self.scheduler.timesteps]
        )

        timestep_id = torch.argmin(
            (timesteps.unsqueeze(0) - timestep.unsqueeze(1)).abs(), dim=1)
        sigma_t = sigmas[timestep_id].reshape(-1, 1, 1, 1)
        x0_pred = xt - sigma_t * flow_pred
        return x0_pred.to(original_dtype)

    @staticmethod
    def _convert_x0_to_flow_pred(scheduler, x0_pred: torch.Tensor, xt: torch.Tensor, timestep: torch.Tensor) -> torch.Tensor:
        """
        Convert x0 prediction to flow matching's prediction.
        x0_pred: the x0 prediction with shape [B, C, H, W]
        xt: the input noisy data with shape [B, C, H, W]
        timestep: the timestep with shape [B]

        pred = (x_t - x_0) / sigma_t
        """
        # use higher precision for calculations
        original_dtype = x0_pred.dtype
        x0_pred, xt, sigmas, timesteps = map(
            lambda x: x.double().to(x0_pred.device), [x0_pred, xt,
                                                      scheduler.sigmas,
                                                      scheduler.timesteps]
        )
        timestep_id = torch.argmin(
            (timesteps.unsqueeze(0) - timestep.unsqueeze(1)).abs(), dim=1)
        sigma_t = sigmas[timestep_id].reshape(-1, 1, 1, 1)
        flow_pred = (xt - x0_pred) / sigma_t
        return flow_pred.to(original_dtype)

    def forward(
        self,
        noisy_image_or_video: torch.Tensor,
        conditional_dict: dict,
        timestep: torch.Tensor,
        kv_cache: Optional[List[dict]] = None,
        crossattn_cache: Optional[List[dict]] = None,
        current_start: Optional[int] = None,
        classify_mode: Optional[bool] = False,
        concat_time_embeddings: Optional[bool] = False,
        clean_x: Optional[torch.Tensor] = None,
        aug_t: Optional[torch.Tensor] = None,
    ) -> torch.Tensor:
        prompt_embeds = conditional_dict["prompt_embeds"]

        if "2.2" in self.model_name and '5B' in self.model_name:
            input_timestep = conditional_dict["wan22_input_timestep"]
        else:
            # [B, F] -> [B]
            if self.uniform_timestep:
                input_timestep = timestep[:, 0]
            else:
                input_timestep = timestep
        
        logits = None
        
        # X0 prediction
        if kv_cache is not None:
            flow_pred = self.model(
                noisy_image_or_video.permute(0, 2, 1, 3, 4),
                t=input_timestep, context=prompt_embeds,
                seq_len=self.seq_len,
                kv_cache=kv_cache, # 用kv cache来预测后续帧
                crossattn_cache=crossattn_cache,
                current_start=current_start,
            ).permute(0, 2, 1, 3, 4)
        else:
            if clean_x is not None:
                # teacher forcing
                flow_pred = self.model(
                    noisy_image_or_video.permute(0, 2, 1, 3, 4),
                    t=input_timestep, context=prompt_embeds,
                    seq_len=self.seq_len,
                    clean_x=clean_x.permute(0, 2, 1, 3, 4),
                    aug_t=aug_t,
                ).permute(0, 2, 1, 3, 4)
            else:
                if classify_mode:
                    flow_pred, logits = self.model(
                        noisy_image_or_video.permute(0, 2, 1, 3, 4),
                        t=input_timestep, context=prompt_embeds,
                        seq_len=self.seq_len,
                        classify_mode=True,
                        register_tokens=self._register_tokens,
                        cls_pred_branch=self._cls_pred_branch,
                        gan_ca_blocks=self._gan_ca_blocks,
                        concat_time_embeddings=concat_time_embeddings,
                    )
                    flow_pred = flow_pred.permute(0, 2, 1, 3, 4)
                else: # 走这个分枝
                    flow_pred = self.model(
                        noisy_image_or_video.permute(0, 2, 1, 3, 4),
                        t=input_timestep, context=prompt_embeds,
                        seq_len=self.seq_len,
                    ).permute(0, 2, 1, 3, 4)

        pred_x0 = self._convert_flow_pred_to_x0(
            flow_pred=flow_pred.flatten(0, 1),
            xt=noisy_image_or_video[:, :, :flow_pred.shape[2], :, :].flatten(0, 1),
            timestep=timestep.flatten(0, 1)
        ).unflatten(0, flow_pred.shape[:2])

        if logits is not None:
            return flow_pred, pred_x0, logits

        return flow_pred, pred_x0

    def get_scheduler(self) -> SchedulerInterface:
        """
        Update the current scheduler with the interface's static method
        """
        scheduler = self.scheduler
        scheduler.convert_x0_to_noise = types.MethodType(
            SchedulerInterface.convert_x0_to_noise, scheduler)
        scheduler.convert_noise_to_x0 = types.MethodType(
            SchedulerInterface.convert_noise_to_x0, scheduler)
        scheduler.convert_velocity_to_x0 = types.MethodType(
            SchedulerInterface.convert_velocity_to_x0, scheduler)
        self.scheduler = scheduler
        return scheduler

    def post_init(self):
        """
        A few custom initialization steps that should be called after the object is created.
        Currently, the only one we have is to bind a few methods to scheduler.
        We can gradually add more methods here if needed.
        """
        self.get_scheduler()
