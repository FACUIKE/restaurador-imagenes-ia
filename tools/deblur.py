import logging
from pathlib import Path
import cv2
import numpy as np
import torch
import torch.nn as nn
import torch.nn.functional as F

from tools.base_tool import BaseRestorationTool
from config import settings

logger = logging.getLogger(__name__)


# -------------------------------------------------------------------------
# Arquitectura NAFNet (Megvii Research) nativa en PyTorch
# -------------------------------------------------------------------------

class SimpleGate(nn.Module):
    def forward(self, x):
        x1, x2 = x.chunk(2, dim=1)
        return x1 * x2


class NAFBlock(nn.Module):
    def __init__(self, c, DW_Expand=2, FFN_Expand=2, drop_out_rate=0.0):
        super().__init__()
        dw_channel = c * DW_Expand
        self.conv1 = nn.Conv2d(c, dw_channel, kernel_size=1, padding=0, stride=1, groups=1, bias=True)
        self.conv2 = nn.Conv2d(dw_channel, dw_channel, kernel_size=3, padding=1, stride=1, groups=dw_channel, bias=True)
        self.conv3 = nn.Conv2d(dw_channel // 2, c, kernel_size=1, padding=0, stride=1, groups=1, bias=True)

        self.sca = nn.Sequential(
            nn.AdaptiveAvgPool2d(1),
            nn.Conv2d(dw_channel // 2, dw_channel // 2, kernel_size=1, padding=0, stride=1, groups=1, bias=True)
        )

        self.sg = SimpleGate()

        ffn_channel = FFN_Expand * c
        self.conv4 = nn.Conv2d(c, ffn_channel, kernel_size=1, padding=0, stride=1, groups=1, bias=True)
        self.conv5 = nn.Conv2d(ffn_channel // 2, c, kernel_size=1, padding=0, stride=1, groups=1, bias=True)

        self.norm1 = nn.GroupNorm(1, c)
        self.norm2 = nn.GroupNorm(1, c)

        self.dropout1 = nn.Dropout(drop_out_rate) if drop_out_rate > 0.0 else nn.Identity()
        self.dropout2 = nn.Dropout(drop_out_rate) if drop_out_rate > 0.0 else nn.Identity()

        self.beta = nn.Parameter(torch.zeros((1, c, 1, 1)), requires_grad=True)
        self.gamma = nn.Parameter(torch.zeros((1, c, 1, 1)), requires_grad=True)

    def forward(self, inp):
        x = inp
        x = self.norm1(x)
        x = self.conv1(x)
        x = self.conv2(x)
        x = self.sg(x)
        x = x * self.sca(x)
        x = self.conv3(x)
        x = self.dropout1(x)
        y = inp + x * self.beta

        x = self.norm2(y)
        x = self.conv4(x)
        x = self.sg(x)
        x = self.conv5(x)
        x = self.dropout2(x)
        return y + x * self.gamma


class NAFNet(nn.Module):
    def __init__(self, img_channel=3, width=32, middle_blk_num=1, enc_blk_nums=[1, 1, 1, 28], dec_blk_nums=[1, 1, 1, 1]):
        super().__init__()
        self.intro = nn.Conv2d(img_channel, width, kernel_size=3, padding=1, stride=1, bias=True)
        self.ending = nn.Conv2d(width, img_channel, kernel_size=3, padding=1, stride=1, bias=True)

        self.encoders = nn.ModuleList()
        self.decoders = nn.ModuleList()
        self.middle_blks = nn.ModuleList()
        self.ups = nn.ModuleList()
        self.downs = nn.ModuleList()

        chan = width
        for num in enc_blk_nums:
            self.encoders.append(nn.Sequential(*[NAFBlock(chan) for _ in range(num)]))
            self.downs.append(nn.Conv2d(chan, 2 * chan, 2, 2))
            chan = chan * 2

        self.middle_blks = nn.Sequential(*[NAFBlock(chan) for _ in range(middle_blk_num)])

        for num in dec_blk_nums:
            self.ups.append(nn.Sequential(
                nn.Conv2d(chan, chan * 2, 1, bias=False),
                nn.PixelShuffle(2)
            ))
            chan = chan // 2
            self.decoders.append(nn.Sequential(*[NAFBlock(chan) for _ in range(num)]))

        self.padder_size = 2 ** len(enc_blk_nums)

    def forward(self, inp):
        B, C, H, W = inp.shape
        pad_h = (self.padder_size - H % self.padder_size) % self.padder_size
        pad_w = (self.padder_size - W % self.padder_size) % self.padder_size
        x = F.pad(inp, (0, pad_w, 0, pad_h), mode='reflect')

        x = self.intro(x)
        encs = []
        for encoder, down in zip(self.encoders, self.downs):
            x = encoder(x)
            encs.append(x)
            x = down(x)

        x = self.middle_blks(x)

        for decoder, up, enc_skip in zip(self.decoders, self.ups, encs[::-1]):
            x = up(x)
            x = x + enc_skip
            x = decoder(x)

        x = self.ending(x)
        x = x + inp
        return x[:, :, :H, :W]


# -------------------------------------------------------------------------
# Tool Wrapper para el Pipeline
# -------------------------------------------------------------------------

class NAFNetDeblurTool(BaseRestorationTool):
    """
    Restaura desenfoque de movimiento en toda la imagen usando NAFNet
    con fallback de realce local si falla la descarga de pesos.
    """
    def __init__(self):
        super().__init__(name="global_deblur")
        self.model = None
        self.use_fallback = False

    def _load_model(self):
        if self.model is not None or self.use_fallback:
            return

        device = "cuda" if torch.cuda.is_available() else "cpu"
        logger.info(f"Cargando NAFNetDeblur en dispositivo: {device}")
        
        try:
            net = NAFNet(
                img_channel=3,
                width=32,
                middle_blk_num=1,
                enc_blk_nums=[1, 1, 1, 28],
                dec_blk_nums=[1, 1, 1, 1]
            )

            # Mirror directo de pesos en Hugging Face
            checkpoint_url = "https://huggingface.co/spaces/WorksOfArt/NAFNet/resolve/main/models/NAFNet-GoPro-width32.pth"
            checkpoint = torch.hub.load_state_dict_from_url(
                checkpoint_url,
                map_location=device,
                progress=True
            )

            state_dict = checkpoint["params"] if "params" in checkpoint else checkpoint
            net.load_state_dict(state_dict)
            net.eval().to(device)
            self.model = net
        except Exception as e:
            logger.warning(f"No se pudo descargar NAFNet ({e}). Activando realce local OpenCV.")
            self.model = None
            self.use_fallback = True

    def process(self, input_path: Path) -> Path:
        self._load_model()
        output_path = settings.OUTPUTS_DIR / f"step_deblur_{input_path.name}"

        img = cv2.imread(str(input_path))
        if img is None:
            raise FileNotFoundError(f"No se pudo abrir la imagen en: {input_path}")

        # Si el modelo no está disponible, usar Unsharp Masking local sin crashear
        if self.use_fallback or self.model is None:
            gaussian = cv2.GaussianBlur(img, (0, 0), sigmaX=2.5)
            sharpened = cv2.addWeighted(img, 1.6, gaussian, -0.6, 0)
            cv2.imwrite(str(output_path), sharpened)
            return output_path

        device = "cuda" if torch.cuda.is_available() else "cpu"

        img_rgb = cv2.cvtColor(img, cv2.COLOR_BGR2RGB)
        tensor = torch.from_numpy(img_rgb).float().div(255.0).permute(2, 0, 1).unsqueeze(0).to(device)

        with torch.no_grad():
            output_tensor = self.model(tensor)
            output_arr = output_tensor.squeeze().permute(1, 2, 0).clamp(0, 1).cpu().numpy()

        result = (output_arr * 255.0).round().astype(np.uint8)
        result_bgr = cv2.cvtColor(result, cv2.COLOR_RGB2BGR)
        cv2.imwrite(str(output_path), result_bgr)

        if torch.cuda.is_available():
            torch.cuda.empty_cache()

        return output_path