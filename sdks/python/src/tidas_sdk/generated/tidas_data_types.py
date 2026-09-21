"""
Auto generated file. DO NOT EDIT.
Source: tidas_data_types.json
"""
from __future__ import annotations

import re

from typing import Annotated, Any, Literal

from pydantic import Field, model_validator
from tidas_sdk.core.base import TidasBaseModel
from tidas_sdk.core.multilang import MultiLangList

from datetime import datetime
from pydantic import AfterValidator
from tidas_sdk.core.cas_number import validate_cas_number_check_digit

CHINESE_CHARACTER_PATTERN = re.compile(r'[\u3400-\u4DBF\u4E00-\u9FFF\uF900-\uFAFF]')

# CAS Number, leading zeros are requried.
CASNumber = Annotated[str, Field(pattern='^[0-9]{2,7}-[0-9]{2}-[0-9]$'), AfterValidator(validate_cas_number_check_digit)]
# Free text with an unlimited length.
FT = str
# TIDAS Languages enumeration.
Languages = Literal['aa', 'ab', 'ae', 'af', 'ak', 'am', 'an', 'ar', 'as', 'av', 'ay', 'az', 'ba', 'be', 'bg', 'bh', 'bi', 'bm', 'bn', 'bo', 'br', 'bs', 'ca', 'ce', 'ch', 'co', 'cr', 'cs', 'cu', 'cv', 'cy', 'da', 'de', 'dv', 'dz', 'ee', 'el', 'en', 'eo', 'es', 'et', 'eu', 'fa', 'ff', 'fi', 'fj', 'fo', 'fr', 'fy', 'ga', 'gd', 'gl', 'gn', 'gu', 'gv', 'ha', 'he', 'hi', 'ho', 'hr', 'ht', 'hu', 'hy', 'hz', 'ia', 'id', 'ie', 'ig', 'ii', 'ik', 'io', 'is', 'it', 'iu', 'ja', 'jv', 'ka', 'kg', 'ki', 'kj', 'kk', 'kl', 'km', 'kn', 'ko', 'kr', 'ks', 'ku', 'kv', 'kw', 'ky', 'la', 'lb', 'lg', 'li', 'ln', 'lo', 'lt', 'lu', 'lv', 'mg', 'mh', 'mi', 'mk', 'ml', 'mn', 'mo', 'mr', 'ms', 'mt', 'my', 'na', 'nb', 'nd', 'ne', 'ng', 'nl', 'nn', 'no', 'nr', 'nv', 'ny', 'oc', 'oj', 'om', 'or', 'os', 'pa', 'pi', 'pl', 'ps', 'pt', 'qu', 'rm', 'rn', 'ro', 'ru', 'rw', 'sa', 'sc', 'sd', 'se', 'sg', 'si', 'sk', 'sl', 'sm', 'sn', 'so', 'sq', 'sr', 'ss', 'st', 'su', 'sv', 'sw', 'ta', 'te', 'tg', 'th', 'ti', 'tk', 'tl', 'tn', 'to', 'tr', 'ts', 'tt', 'tw', 'ty', 'ug', 'uk', 'ur', 'uz', 've', 'vi', 'vo', 'wa', 'wo', 'xh', 'yi', 'yo', 'za', 'zh', 'zu']
# 1-digit integer number
Int1 = Annotated[str, Field(pattern='^[0-9]$')]
# 5-digit integer number
Int5 = Annotated[str, Field(pattern='^(0|[1-9]\\d{0,4})$')]
# 6-digit integer number
Int6 = Annotated[str, Field(pattern='^(0|[1-9]\\d{0,5})$')]
# 1-digit integer number, must be equal to or greater than 0
LevelType = Int1
# percentage amount (ILCD Perc: decimal, totalDigits=5, fractionDigits=3)
Perc = Annotated[str, Field(pattern='^[+-]?(\\d{1,5}|\\d{1,4}\\.\\d|\\d{1,3}\\.\\d{2}|\\d{1,2}\\.\\d{3})$')]
# Mathematical rule
MatR = str
# Mathematical variable or parameter
MatV = str
# 38-digit real number
Real = Annotated[str, Field(pattern='^[+-]?(\\d+(\\.\\d*)?|\\.\\d+)([Ee][+-]?\\d+)?$')]
# Short text with a maximum length of 1000 characters
ST = Annotated[str, Field(max_length=1000)]
# String with a maximum length of 500 characters. Must have a minimum length of 1.
String = Annotated[str, Field(min_length=1, max_length=500)]
# JSON representation of an arbitrary XML element payload.
AnyXmlElement = Any
# ILCD common:other extension container. The container must include at least one non-common extension element; namespace declarations are allowed but do not count as extension content.
_COMMON_OTHER_NAMESPACE_DECLARATION_PATTERN = re.compile(
    r'^@xmlns(:[A-Za-z_][A-Za-z0-9_.-]*)?$'
)
_COMMON_OTHER_EXTENSION_ELEMENT_PATTERN = re.compile(
    r'^(?!(common|xmlns):)([A-Za-z_][A-Za-z0-9_.-]*:)?[A-Za-z_][A-Za-z0-9_.-]*$'
)

def _validate_common_other(value: dict[str, AnyXmlElement]) -> dict[str, AnyXmlElement]:
    has_extension_element = False

    for key, entry_value in value.items():
        if _COMMON_OTHER_NAMESPACE_DECLARATION_PATTERN.fullmatch(key):
            if not isinstance(entry_value, str):
                raise ValueError("Namespace declarations in common:other must be strings")
            continue

        if _COMMON_OTHER_EXTENSION_ELEMENT_PATTERN.fullmatch(key):
            has_extension_element = True
            continue

        raise ValueError(
            "common:other entries must be namespace declarations or non-common extension elements"
        )

    if not has_extension_element:
        raise ValueError("common:other must include at least one non-common extension element")

    return value

CommonOther = Annotated[dict[str, AnyXmlElement], AfterValidator(_validate_common_other)]
# Global geographical reference in Latitude and LongitudeExamples: "+42.42;-180", "0;0", "13.22 ; -3"
GIS = Annotated[str, Field(pattern='^\\s*[+-]?((90(\\.0+)?)|([0-8]?\\d(\\.\\d+)?))\\s*;\\s*[+-]?((180(\\.0+)?)|((1[0-7]\\d|[0-9]?\\d)(\\.\\d+)?))\\s*$')]
# Unique Universal Identifier, 16-byte hex number
UUID = Annotated[str, Field(pattern='^[0-9a-f]{8}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{12}$')]
# Data set version number, format NN.NN(.NNN) per ILCD.
Version = Annotated[str, Field(pattern='^\\d{2}\\.\\d{2}(\\.\\d{3})?$')]
# Type of the referenced dataset/file (ILCD GlobalReferenceTypeValues).
GlobalReferenceTypeValues = Literal['source data set', 'process data set', 'flow data set', 'flow property data set', 'unit group data set', 'contact data set', 'LCIA method data set', 'other external file']
# 4-digit year
Year = Annotated[int, Field(ge=1000, le=9999)]
# Date and time format acc. to ISO 8601
DateTime = datetime

class LocalizedTextItem(TidasBaseModel):
    """Language-tagged text with optional script checks for selected languages."""
    xml_lang: Languages = Field(default=..., alias='@xml:lang')
    text: str = Field(default=..., alias='#text')

    @model_validator(mode='after')
    def _validate_language_script(self) -> 'LocalizedTextItem':
        if self.xml_lang == 'zh' and not CHINESE_CHARACTER_PATTERN.search(self.text):
            raise ValueError("@xml:lang value 'zh' must include at least one Chinese character")
        if self.xml_lang == 'en' and CHINESE_CHARACTER_PATTERN.search(self.text):
            raise ValueError("@xml:lang value 'en' must not contain Chinese characters")
        return self

class LocalizedText500Item(LocalizedTextItem):
    """Language-tagged text with a maximum length of 500 characters."""
    xml_lang: Languages = Field(default=..., alias='@xml:lang')
    text: str = Field(default=..., alias='#text', max_length=500)

    @model_validator(mode='after')
    def _validate_language_script(self) -> 'LocalizedText500Item':
        if self.xml_lang == 'zh' and not CHINESE_CHARACTER_PATTERN.search(self.text):
            raise ValueError("@xml:lang value 'zh' must include at least one Chinese character")
        if self.xml_lang == 'en' and CHINESE_CHARACTER_PATTERN.search(self.text):
            raise ValueError("@xml:lang value 'en' must not contain Chinese characters")
        return self

class AnnualSupplyOrProductionVolumeTextItem(LocalizedText500Item):
    """Language-tagged annual supply or production volume text. The text must start with a real number followed by whitespace and a non-empty unit or context suffix."""
    xml_lang: Languages = Field(default=..., alias='@xml:lang')
    text: str = Field(default=..., alias='#text', max_length=500, pattern='^[+-]?(\\d+(\\.\\d*)?|\\.\\d+)([Ee][+-]?\\d+)?\\s+\\S.*$')

class LocalizedText1000Item(LocalizedTextItem):
    """Language-tagged text with a maximum length of 1000 characters."""
    xml_lang: Languages = Field(default=..., alias='@xml:lang')
    text: str = Field(default=..., alias='#text', max_length=1000)

    @model_validator(mode='after')
    def _validate_language_script(self) -> 'LocalizedText1000Item':
        if self.xml_lang == 'zh' and not CHINESE_CHARACTER_PATTERN.search(self.text):
            raise ValueError("@xml:lang value 'zh' must include at least one Chinese character")
        if self.xml_lang == 'en' and CHINESE_CHARACTER_PATTERN.search(self.text):
            raise ValueError("@xml:lang value 'en' must not contain Chinese characters")
        return self

class GlobalReferenceTypeVariant0(TidasBaseModel):
    type: GlobalReferenceTypeValues = Field(default=..., alias='@type')
    ref_object_id: str = Field(default=..., alias='@refObjectId', pattern='^[0-9a-f]{8}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{12}$')
    version: Version = Field(default=..., alias='@version')
    uri: str = Field(default=..., alias='@uri')
    common_short_description: MultiLangList = Field(default=..., alias='common:shortDescription')
    common_sub_reference: Annotated[list[String], Field(min_length=1)] | String | None = Field(default=None, alias='common:subReference', description='Optional sub-reference (e.g. section or page) within the referenced source.')

class GlobalReferenceTypeVariant1Item(TidasBaseModel):
    type: GlobalReferenceTypeValues = Field(default=..., alias='@type')
    ref_object_id: str = Field(default=..., alias='@refObjectId', pattern='^[0-9a-f]{8}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{4}-[0-9a-f]{12}$')
    version: Version = Field(default=..., alias='@version')
    uri: str = Field(default=..., alias='@uri')
    common_short_description: MultiLangList = Field(default=..., alias='common:shortDescription')
    common_sub_reference: Annotated[list[String], Field(min_length=1)] | String | None = Field(default=None, alias='common:subReference', description='Optional sub-reference (e.g. section or page) within the referenced source.')

class DataTypes(TidasBaseModel):
    pass

# Multi-language annual supply or production volume text with a numeric prefix and unit or context suffix.
AnnualSupplyOrProductionVolumeMultiLang = list[AnnualSupplyOrProductionVolumeTextItem] | AnnualSupplyOrProductionVolumeTextItem
# Multi-language string with a maximum length of 500 characters
StringMultiLang = list[LocalizedText500Item] | LocalizedText500Item
# Multi-lang short text with a maximum length of 1000 characters.
STMultiLang = list[LocalizedText1000Item] | LocalizedText1000Item
# Multi-lang free text with an unlimited length.
FTMultiLang = list[LocalizedTextItem] | LocalizedTextItem
# Represents a reference to another dataset or file. In TIDAS, references must include type, refObjectId, version, uri, and shortDescription.
GlobalReferenceType = GlobalReferenceTypeVariant0 | list[GlobalReferenceTypeVariant1Item]
